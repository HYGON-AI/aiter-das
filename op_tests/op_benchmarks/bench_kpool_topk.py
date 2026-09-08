import argparse
import copy
import math
import os
from contextlib import contextmanager
from typing import Optional

import torch

from aiter import kpool_topk


FALLBACK_ENV = "SGL_KERNEL_KPOOL_TOPK_FORCE_FALLBACK"
DEFAULT_PREFILL_KV_LENS = [
    1 * 1024,
    2 * 1024,
    4 * 1024,
    8 * 1024,
    16 * 1024,
    32 * 1024,
    64 * 1024,
    79 * 1024,
    128 * 1024,
    256 * 1024,
    512 * 1024,
    1024 * 1024,
]
DEFAULT_DECODE_KV_LENS = [128 * 1024, 256 * 1024, 512 * 1024, 1024 * 1024]
DEFAULT_GROUP_TOPKS = {
    4: [512],
    16: [128],
}


@contextmanager
def fallback_mode(enabled: bool):
    old = os.environ.get(FALLBACK_ENV)
    if enabled:
        os.environ[FALLBACK_ENV] = "1"
    else:
        os.environ.pop(FALLBACK_ENV, None)
    try:
        yield
    finally:
        if old is None:
            os.environ.pop(FALLBACK_ENV, None)
        else:
            os.environ[FALLBACK_ENV] = old


def make_shuffled_page_table(rows, num_groups, pool_size, token_cols, device):
    table = torch.arange(rows * token_cols, dtype=torch.int32, device=device).view(
        rows, token_cols
    )
    group_table = table[:, : num_groups * pool_size].view(rows, num_groups, pool_size)
    group_out = torch.empty_like(group_table)
    for row in range(rows):
        group_out[row] = group_table[row, torch.randperm(num_groups, device=device)]
    out = table.clone()
    out[:, : num_groups * pool_size] = group_out.reshape(rows, num_groups * pool_size)
    return out


def make_case(args, group_topk):
    device = torch.device(args.device)
    topk = group_topk * args.pool_size
    page_table = None
    page_table_row_index = None
    offsets = None
    row_starts = None

    if args.stage == "decode":
        rows = args.bs
        if args.num_groups is None:
            num_groups = math.ceil(args.decode_kv_len / args.pool_size)
        else:
            num_groups = args.num_groups
        score_cols = rows * num_groups if args.decode_layout == "packed" else num_groups
        score = torch.randn(rows, score_cols, dtype=torch.float32, device=device)
        lengths = torch.full((rows,), num_groups, dtype=torch.int32, device=device)
        kv_len = args.decode_kv_len if args.decode_kv_len is not None else num_groups * args.pool_size
        if args.decode_layout == "packed":
            row_starts = torch.arange(rows, dtype=torch.int32, device=device) * num_groups
    else:
        rows = args.seq_len
        kv_len = args.kv_len if args.kv_len is not None else args.seq_len
        num_groups = math.ceil(kv_len / args.pool_size)
        group_len = num_groups if args.group_lengths == "ceil" else kv_len // args.pool_size
        score = torch.randn(rows, num_groups, dtype=torch.float32, device=device)
        lengths = torch.full((rows,), group_len, dtype=torch.int32, device=device)
        row_starts = torch.zeros(rows, dtype=torch.int32, device=device)

    if args.mode == "paged":
        page_table_rows = rows + 3 if args.page_table_row_index else rows
        token_cols = num_groups * args.pool_size + (
            args.pool_size - 1 if args.append_tail else 0
        )
        page_table = make_shuffled_page_table(
            page_table_rows, num_groups, args.pool_size, token_cols, device
        )
        if args.page_table_row_index:
            page_table_row_index = (
                torch.arange(rows, dtype=torch.int32, device=device) * 7
            ) % page_table_rows
    elif args.mode == "ragged":
        offsets = torch.arange(rows, dtype=torch.int32, device=device)
    elif args.mode != "raw":
        raise ValueError(args.mode)

    seq_lens = None
    if args.append_tail:
        seq_lens = torch.full((rows,), kv_len, dtype=torch.int32, device=device)

    out_rows = args.out_rows if args.out_rows is not None else rows
    return {
        "score": score,
        "lengths": lengths,
        "pool_size": args.pool_size,
        "topk": topk,
        "page_table": page_table,
        "page_table_row_index": page_table_row_index,
        "offsets": offsets,
        "row_starts": row_starts,
        "seq_lens": seq_lens,
        "out_rows": out_rows,
        "meta": {
            "stage": args.stage,
            "layout": args.decode_layout if args.stage == "decode" else "-",
            "mode": args.mode,
            "score": tuple(score.shape),
            "rows": rows,
            "num_groups": num_groups,
            "context": kv_len,
            "pool_size": args.pool_size,
            "group_topk": group_topk,
            "topk": topk,
        },
    }


@torch.inference_mode()
def ref_kpool(case):
    score = case["score"]
    lengths = case["lengths"]
    pool_size = case["pool_size"]
    topk = case["topk"]
    page_table = case["page_table"]
    page_table_row_index = case["page_table_row_index"]
    offsets = case["offsets"]
    row_starts = case["row_starts"]
    seq_lens = case["seq_lens"]
    out_rows = case["out_rows"]

    rows = score.shape[0]
    group_topk = topk // pool_size
    token_offsets = torch.arange(pool_size, dtype=torch.int32, device=score.device)
    out_cols = topk + (pool_size - 1 if seq_lens is not None else 0)
    out = torch.full((out_rows, out_cols), -1, dtype=torch.int32, device=score.device)
    for row in range(rows):
        row_start = int(row_starts[row].item()) if row_starts is not None else 0
        length = int(lengths[row].item())
        valid_count = min(length, group_topk)
        write_pos = 0
        if valid_count > 0:
            if length <= group_topk:
                selected = torch.arange(length, dtype=torch.int32, device=score.device)
            else:
                selected = torch.topk(
                    score[row, row_start : row_start + length],
                    group_topk,
                    dim=-1,
                    sorted=False,
                ).indices.to(torch.int32)
            raw = (selected.unsqueeze(1) * pool_size + token_offsets).reshape(-1)
            if page_table is not None:
                pt_row = (
                    int(page_table_row_index[row].item())
                    if page_table_row_index is not None
                    else row
                )
                token_ids = page_table[pt_row, raw.long()].to(torch.int32)
            elif offsets is not None:
                token_ids = raw + offsets[row].to(torch.int32)
            else:
                token_ids = raw
            write_pos = valid_count * pool_size
            out[row, :write_pos] = token_ids[:write_pos]
        if seq_lens is not None:
            tail_count = int(seq_lens[row].item()) % pool_size
            if tail_count > 0:
                raw_tail = length * pool_size + torch.arange(
                    tail_count, dtype=torch.int32, device=score.device
                )
                if page_table is not None:
                    pt_row = (
                        int(page_table_row_index[row].item())
                        if page_table_row_index is not None
                        else row
                    )
                    tail = page_table[pt_row, raw_tail.long()].to(torch.int32)
                elif offsets is not None:
                    tail = raw_tail + offsets[row].to(torch.int32)
                else:
                    tail = raw_tail
                out[row, write_pos : write_pos + tail_count] = tail
    return out


def call_impl(name, case):
    force_fallback = name in ("fallback", "opt_fallback")
    if name in ("fallback", "opt", "opt_fallback"):
        with fallback_mode(force_fallback):
            return kpool_topk(
                case["score"],
                case["lengths"],
                case["pool_size"],
                case["topk"],
                page_table=case["page_table"],
                topk_indices_offset=case["offsets"],
                row_starts=case["row_starts"],
                seq_lens=case["seq_lens"],
                out_rows=case["out_rows"],
                page_table_row_index=case["page_table_row_index"],
            )
    raise ValueError(name)


def approx_bytes(case, out_shape):
    score_bytes = case["score"].numel() * case["score"].element_size()
    lengths_bytes = case["lengths"].numel() * case["lengths"].element_size()
    page_bytes = 0
    if case["page_table"] is not None:
        # The kernel reads selected topk token ids, not the full page table.
        page_bytes = out_shape[0] * out_shape[1] * case["page_table"].element_size()
    output_bytes = out_shape[0] * out_shape[1] * 4
    return score_bytes + lengths_bytes + page_bytes + output_bytes


def _invert_token_mapping(tokens, row, pool_size, offsets, page_table, page_table_row_index):
    valid = tokens[tokens >= 0]
    if valid.numel() == 0:
        return valid

    if page_table is not None:
        pt_row = (
            int(page_table_row_index[row].item())
            if page_table_row_index is not None
            else row
        )
        table = page_table[pt_row]
        positions = []
        for token in valid:
            match = torch.nonzero(table == token, as_tuple=False).flatten()
            if match.numel() > 0:
                positions.append(match[0])
        if not positions:
            return valid[:0]
        return (torch.stack(positions).to(torch.int32) // pool_size).unique()

    if offsets is not None:
        valid = valid - offsets[row].to(torch.int32)

    return (valid // pool_size).unique()


def equal_or_score_tie(case, out, ref):
    out_sorted = torch.sort(out, dim=-1).values
    ref_sorted = torch.sort(ref, dim=-1).values
    if torch.equal(out_sorted, ref_sorted):
        return True

    score = case["score"]
    lengths = case["lengths"]
    pool_size = case["pool_size"]
    offsets = case["offsets"]
    page_table = case["page_table"]
    page_table_row_index = case["page_table_row_index"]

    mismatch = (out_sorted != ref_sorted).any(dim=-1)
    rows = torch.nonzero(mismatch, as_tuple=False).flatten()
    for row_tensor in rows:
        row = int(row_tensor.item())
        out_groups = _invert_token_mapping(
            out[row], row, pool_size, offsets, page_table, page_table_row_index
        )
        ref_groups = _invert_token_mapping(
            ref[row], row, pool_size, offsets, page_table, page_table_row_index
        )
        extra = sorted(set(out_groups.detach().cpu().tolist()) - set(ref_groups.detach().cpu().tolist()))
        missing = sorted(set(ref_groups.detach().cpu().tolist()) - set(out_groups.detach().cpu().tolist()))
        if len(extra) != len(missing):
            return False
        for extra_group, missing_group in zip(extra, missing):
            length = int(lengths[row].item())
            if extra_group >= length or missing_group >= length:
                return False
            if score[row, extra_group].item() != score[row, missing_group].item():
                return False
    return True


@torch.inference_mode()
def bench_impl(name, case, args):
    out = call_impl(name, case)
    torch.cuda.synchronize()
    for _ in range(args.warmup):
        call_impl(name, case)
    torch.cuda.synchronize()
    times = []
    for _ in range(args.repeats):
        start = torch.cuda.Event(enable_timing=True)
        end = torch.cuda.Event(enable_timing=True)
        start.record()
        for _ in range(args.iters):
            out = call_impl(name, case)
        end.record()
        torch.cuda.synchronize()
        times.append(start.elapsed_time(end) / args.iters)
    return out, times


def expand_impls(impls, stage):
    if "both" in impls:
        return ["fallback", "opt"]
    if "all" in impls:
        return ["fallback", "opt"]
    return impls


def format_kv_len(value):
    if value % 1024 == 0:
        return f"{value // 1024}K"
    return str(value)


def print_aligned_table(columns, rows):
    widths = [len(col) for col in columns]
    for row in rows:
        for i, value in enumerate(row):
            widths[i] = max(widths[i], len(str(value)))

    def fmt(row):
        cells = []
        for i, value in enumerate(row):
            text = str(value)
            if i == 1:
                cells.append(text.rjust(widths[i]))
            elif i >= 2:
                cells.append(text.rjust(widths[i]))
            else:
                cells.append(text.ljust(widths[i]))
        return "  ".join(cells)

    print(fmt(columns))
    print(fmt(["-" * width for width in widths]))
    for row in rows:
        print(fmt(row))


STREAM_COLUMNS = [
    "rows",
    "kv_len",
    "fallback_ms",
    "opt_ms",
    "speedup",
    "fallback_GBps",
    "opt_GBps",
]
STREAM_WIDTHS = [max(len(col), width) for col, width in zip(STREAM_COLUMNS, [4, 6, 11, 7, 7, 13, 8])]


def format_stream_row(row):
    cells = []
    for i, value in enumerate(row):
        text = str(value)
        if i == 0:
            cells.append(text.ljust(STREAM_WIDTHS[i]))
        else:
            cells.append(text.rjust(STREAM_WIDTHS[i]))
    return "  ".join(cells)


def print_stream_header(meta, out_shape, status):
    print()
    print(
        "stage={} layout={} mode={} pool_size={} group_topk={} topk={} out={} check={}".format(
            meta["stage"],
            meta["layout"],
            meta["mode"],
            meta["pool_size"],
            meta["group_topk"],
            meta["topk"],
            out_shape,
            status,
        ),
        flush=True,
    )
    print(format_stream_row(STREAM_COLUMNS), flush=True)
    print(format_stream_row(["-" * width for width in STREAM_WIDTHS]), flush=True)


def make_result_row(meta, impl_results):
    fallback = impl_results.get("fallback")
    opt = impl_results.get("opt")
    fallback_ms = f"{fallback['best']:.5f}" if fallback is not None else "-"
    opt_ms = f"{opt['best']:.5f}" if opt is not None else "-"
    speedup = (
        f"{fallback['best'] / opt['best']:.2f}x"
        if fallback is not None and opt is not None
        else "-"
    )
    fallback_gbps = f"{fallback['gbps']:.2f}" if fallback is not None else "-"
    opt_gbps = f"{opt['gbps']:.2f}" if opt is not None else "-"
    rows = meta["score"][0]
    return [
        rows,
        format_kv_len(meta["context"]),
        fallback_ms,
        opt_ms,
        speedup,
        fallback_gbps,
        opt_gbps,
    ]


def run(args):
    torch.manual_seed(args.seed)

    print(
        f"torch={torch.__version__} hip={torch.version.hip} "
        f"device={torch.cuda.get_device_name(0)}",
        flush=True,
    )

    stream_header = None
    for case_args in iter_case_args(args):
        impls = expand_impls(args.impl, case_args.stage)
        for group_topk in group_topks_for_pool(args, case_args.pool_size):
            case = make_case(case_args, group_topk)
            ref = ref_kpool(case) if args.check else None
            meta = case["meta"]
            case_impls = {}
            case_status = "-"
            out_shape = None
            for impl in impls:
                out, times = bench_impl(impl, case, case_args)
                status = "-"
                if ref is not None:
                    status = "ok" if equal_or_score_tie(case, out, ref) else "FAIL"
                best = min(times)
                bytes_moved = approx_bytes(case, tuple(out.shape))
                gbps = bytes_moved / (best * 1e-3) / 1e9
                impl_result = {
                    "best": best,
                    "gbps": gbps,
                    "times": times,
                }
                case_impls[impl] = impl_result
                out_shape = tuple(out.shape)
                if status == "FAIL":
                    case_status = "FAIL"
                elif case_status != "FAIL":
                    case_status = status

            current_header = (
                meta["stage"],
                meta["layout"],
                meta["mode"],
                meta["pool_size"],
                meta["group_topk"],
                meta["topk"],
                out_shape,
                case_status,
            )
            if current_header != stream_header:
                print_stream_header(meta, out_shape, case_status)
                stream_header = current_header
            print(format_stream_row(make_result_row(meta, case_impls)), flush=True)


def iter_case_args(args):
    stages = ["prefill", "decode"] if args.stage == "both" else [args.stage]
    for stage in stages:
        if stage == "prefill":
            for pool_size in args.pool_size:
                for seq_len in args.seq_len:
                    for kv_len in args.kv_len:
                        case_args = copy.copy(args)
                        case_args.stage = "prefill"
                        case_args.mode = args.mode or "ragged"
                        case_args.pool_size = pool_size
                        case_args.seq_len = seq_len
                        case_args.kv_len = kv_len
                        yield case_args
        else:
            for pool_size in args.pool_size:
                for decode_kv_len in args.decode_kv_len:
                    case_args = copy.copy(args)
                    case_args.stage = "decode"
                    case_args.mode = args.mode or "paged"
                    case_args.pool_size = pool_size
                    case_args.decode_kv_len = decode_kv_len
                    yield case_args


def group_topks_for_pool(args, pool_size):
    if args.group_topk is not None:
        return args.group_topk
    return DEFAULT_GROUP_TOPKS.get(pool_size, [2048 // pool_size])


def parse_args():
    parser = argparse.ArgumentParser()
    parser.add_argument("--stage", choices=["decode", "prefill", "both"], default="both")
    parser.add_argument("--mode", choices=["raw", "paged", "ragged"], default=None)
    parser.add_argument(
        "--impl",
        nargs="+",
        default=["both"],
        choices=[
            "fallback",
            "opt",
            "opt_fallback",
            "both",
            "all",
        ],
    )
    parser.add_argument("--pool-size", type=int, nargs="+", default=[16, 4])
    parser.add_argument("--group-topk", type=int, nargs="+", default=None)
    parser.add_argument("--bs", type=int, default=48)
    parser.add_argument("--num-groups", type=int, default=None)
    parser.add_argument("--decode-kv-len", type=int, nargs="+", default=DEFAULT_DECODE_KV_LENS)
    parser.add_argument("--decode-layout", choices=["normal", "packed"], default="normal")
    parser.add_argument("--page-table-row-index", action="store_true")
    parser.add_argument("--seq-len", type=int, nargs="+", default=[4096])
    parser.add_argument(
        "--kv-len",
        type=int,
        nargs="+",
        default=DEFAULT_PREFILL_KV_LENS,
    )
    parser.add_argument("--group-lengths", choices=["floor", "ceil"], default="ceil")
    parser.add_argument("--append-tail", action=argparse.BooleanOptionalAction, default=True)
    parser.add_argument("--out-rows", type=int, default=None)
    parser.add_argument("--warmup", type=int, default=20)
    parser.add_argument("--iters", type=int, default=100)
    parser.add_argument("--repeats", type=int, default=5)
    parser.add_argument("--check", action="store_true")
    parser.add_argument("--seed", type=int, default=42)
    parser.add_argument("--device", default="cuda")
    return parser.parse_args()


if __name__ == "__main__":
    run(parse_args())
