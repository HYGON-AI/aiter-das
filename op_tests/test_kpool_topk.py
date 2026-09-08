import argparse
import math
import sys
from dataclasses import dataclass
from typing import Iterable

import torch

from aiter import kpool_topk


@dataclass(frozen=True)
class Case:
    stage: str
    seq_len: int
    kv_len: int
    pool_size: int
    group_topk: int
    group_lengths: str
    append_tail: bool
    mode: str
    use_page_table_row_index: bool


def parse_int_list(text: str) -> list[int]:
    return [int(x) for x in text.replace(",", " ").split() if x]


def make_cases(
    stages: Iterable[str],
    seq_lens: Iterable[int],
    kv_lens: Iterable[int],
    pool_sizes: Iterable[int],
    group_topks: Iterable[int],
    group_lengths: Iterable[str],
    append_tail_values: Iterable[bool],
    modes: Iterable[str],
    page_table_row_index_values: Iterable[bool],
) -> list[Case]:
    cases: list[Case] = []
    for stage in stages:
        for seq_len in seq_lens:
            for kv_len in kv_lens:
                for pool_size in pool_sizes:
                    for group_topk in group_topks:
                        for group_len_mode in group_lengths:
                            for append_tail in append_tail_values:
                                for mode in modes:
                                    for use_row_index in page_table_row_index_values:
                                        if mode != "paged" and use_row_index:
                                            continue
                                        cases.append(
                                            Case(
                                                stage=stage,
                                                seq_len=seq_len,
                                                kv_len=kv_len,
                                                pool_size=pool_size,
                                                group_topk=group_topk,
                                                group_lengths=group_len_mode,
                                                append_tail=append_tail,
                                                mode=mode,
                                                use_page_table_row_index=use_row_index,
                                            )
                                        )
    return cases


def make_shuffled_page_table(
    rows: int,
    num_groups: int,
    pool_size: int,
    token_cols: int,
    device: torch.device,
) -> torch.Tensor:
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


@torch.inference_mode()
def python_reference(
    score: torch.Tensor,
    lengths: torch.Tensor,
    pool_size: int,
    group_topk: int,
    offsets: torch.Tensor | None,
    row_starts: torch.Tensor,
    seq_lens: torch.Tensor | None,
    page_table: torch.Tensor | None,
    page_table_row_index: torch.Tensor | None,
) -> torch.Tensor:
    rows = score.shape[0]
    topk = group_topk * pool_size
    token_offsets = torch.arange(pool_size, dtype=torch.int32, device=score.device)
    out_cols = topk + (pool_size - 1 if seq_lens is not None else 0)
    out = torch.full((rows, out_cols), -1, dtype=torch.int32, device=score.device)

    for row in range(rows):
        row_start = int(row_starts[row].item())
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


def first_mismatch(out: torch.Tensor, ref: torch.Tensor) -> str:
    out_sorted = torch.sort(out, dim=-1).values
    ref_sorted = torch.sort(ref, dim=-1).values
    mismatch = (out_sorted != ref_sorted).any(dim=-1)
    rows = torch.nonzero(mismatch, as_tuple=False).flatten()
    if rows.numel() == 0:
        return "unknown mismatch"
    row = int(rows[0].item())
    out_row = out_sorted[row].detach().cpu()
    ref_row = ref_sorted[row].detach().cpu()
    bad_cols = torch.nonzero(out_row != ref_row, as_tuple=False).flatten()
    col = int(bad_cols[0].item()) if bad_cols.numel() else -1
    return (
        f"row={row} col={col} "
        f"out={out_row[col].item() if col >= 0 else 'n/a'} "
        f"ref={ref_row[col].item() if col >= 0 else 'n/a'}"
    )


def _invert_token_mapping(
    tokens: torch.Tensor,
    row: int,
    pool_size: int,
    offsets: torch.Tensor | None,
    page_table: torch.Tensor | None,
    page_table_row_index: torch.Tensor | None,
) -> torch.Tensor:
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


def equal_or_score_tie(
    score: torch.Tensor,
    lengths: torch.Tensor,
    pool_size: int,
    offsets: torch.Tensor | None,
    page_table: torch.Tensor | None,
    page_table_row_index: torch.Tensor | None,
    out: torch.Tensor,
    ref: torch.Tensor,
) -> bool:
    out_sorted = torch.sort(out, dim=-1).values
    ref_sorted = torch.sort(ref, dim=-1).values
    if torch.equal(out_sorted, ref_sorted):
        return True

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
def run_case(case: Case, seed: int, device: torch.device) -> bool:
    torch.manual_seed(seed)
    topk = case.group_topk * case.pool_size
    num_groups = math.ceil(case.kv_len / case.pool_size)
    length = num_groups if case.group_lengths == "ceil" else case.kv_len // case.pool_size

    score = torch.randn(case.seq_len, num_groups, dtype=torch.float32, device=device)
    lengths = torch.full((case.seq_len,), length, dtype=torch.int32, device=device)
    offsets = (
        torch.arange(case.seq_len, dtype=torch.int32, device=device)
        if case.mode == "ragged"
        else None
    )
    row_starts = torch.zeros(case.seq_len, dtype=torch.int32, device=device)
    page_table = None
    page_table_row_index = None
    if case.mode == "paged":
        page_table_rows = (
            case.seq_len + 3 if case.use_page_table_row_index else case.seq_len
        )
        token_cols = num_groups * case.pool_size + (
            case.pool_size - 1 if case.append_tail else 0
        )
        page_table = make_shuffled_page_table(
            page_table_rows, num_groups, case.pool_size, token_cols, device
        )
        if case.use_page_table_row_index:
            page_table_row_index = (
                torch.arange(case.seq_len, dtype=torch.int32, device=device) * 7
            ) % page_table_rows
    seq_lens = (
        torch.full((case.seq_len,), case.kv_len, dtype=torch.int32, device=device)
        if case.append_tail
        else None
    )

    kwargs = dict(
        page_table=page_table,
        topk_indices_offset=offsets,
        row_starts=row_starts,
        seq_lens=seq_lens,
        page_table_row_index=page_table_row_index,
    )
    if case.stage in ("prefill", "decode"):
        out = kpool_topk(
            score,
            lengths,
            case.pool_size,
            topk,
            **kwargs,
        )
    else:
        raise ValueError(case.stage)

    ref = python_reference(
        score,
        lengths,
        case.pool_size,
        case.group_topk,
        offsets,
        row_starts,
        seq_lens,
        page_table,
        page_table_row_index,
    )

    strict_ok = torch.equal(torch.sort(out, dim=-1).values, torch.sort(ref, dim=-1).values)
    ok = strict_ok or equal_or_score_tie(
        score,
        lengths,
        case.pool_size,
        offsets,
        page_table,
        page_table_row_index,
        out,
        ref,
    )
    status = "PASS" if strict_ok else ("PASS_TIE" if ok else "FAIL")
    print(
        f"{status} stage={case.stage} seq={case.seq_len} kv={case.kv_len} "
        f"groups={num_groups} length={length} pool={case.pool_size} "
        f"group_topk={case.group_topk} lengths={case.group_lengths} "
        f"tail={case.append_tail} mode={case.mode} "
        f"page_row_index={case.use_page_table_row_index}",
        flush=True,
    )
    if not ok:
        print("  " + first_mismatch(out, ref), flush=True)
    return ok


def parse_args() -> argparse.Namespace:
    parser = argparse.ArgumentParser()
    parser.add_argument(
        "--stages",
        nargs="+",
        choices=["prefill", "decode"],
        default=["prefill", "decode"],
    )
    parser.add_argument(
        "--seq-lens",
        default="1,2,7,31,128,512,2048",
        help="Comma/space separated sequence lengths.",
    )
    parser.add_argument(
        "--kv-lens",
        default=(
            "1,15,16,17,2047,2048,2049,4095,4096,4097,"
            "61440,65536,81920,131072,262144,524288,1048576"
        ),
        help="Comma/space separated KV lengths.",
    )
    parser.add_argument("--pool-sizes", default="16")
    parser.add_argument("--group-topks", default="128")
    parser.add_argument(
        "--modes",
        nargs="+",
        choices=["raw", "ragged", "paged"],
        default=["raw", "ragged", "paged"],
    )
    parser.add_argument(
        "--group-lengths",
        nargs="+",
        choices=["floor", "ceil"],
        default=["floor", "ceil"],
    )
    parser.add_argument("--append-tail", action=argparse.BooleanOptionalAction, default=True)
    parser.add_argument("--include-no-tail", action="store_true")
    parser.add_argument(
        "--include-page-table-row-index",
        action=argparse.BooleanOptionalAction,
        default=True,
    )
    parser.add_argument("--seed", type=int, default=42)
    parser.add_argument("--device", default="cuda")
    parser.add_argument("--fail-fast", action="store_true")
    return parser.parse_args()


def main() -> int:
    args = parse_args()
    device = torch.device(args.device)
    append_tail_values = [args.append_tail]
    if args.include_no_tail:
        append_tail_values = [False, True]
    page_table_row_index_values = (
        [False, True] if args.include_page_table_row_index else [False]
    )

    cases = make_cases(
        args.stages,
        parse_int_list(args.seq_lens),
        parse_int_list(args.kv_lens),
        parse_int_list(args.pool_sizes),
        parse_int_list(args.group_topks),
        args.group_lengths,
        append_tail_values,
        args.modes,
        page_table_row_index_values,
    )

    failed = 0
    print(f"running {len(cases)} cases on {torch.cuda.get_device_name(0)}", flush=True)
    for i, case in enumerate(cases):
        ok = run_case(case, args.seed + i, device)
        failed += 0 if ok else 1
        if failed and args.fail_fast:
            break

    if failed:
        print(f"FAILED {failed}/{len(cases)} cases", flush=True)
        return 1
    print(f"PASSED {len(cases)} cases", flush=True)
    return 0


if __name__ == "__main__":
    sys.exit(main())
