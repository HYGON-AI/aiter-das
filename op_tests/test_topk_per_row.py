# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
# SPDX-License-Identifier: MIT
"""Correctness + perf summary for topk_per_row (k=2048).

Run: python op_tests/test_topk_per_row.py
"""

from __future__ import annotations

import sys

import pandas as pd
import torch

from aiter.ops.topk_per_row import TOPK, topk_per_row_decode, topk_per_row_prefill
from aiter.test_common import run_perftest

PERF_ITERS = 50
PERF_WARMUP = 10


def _ref_prefill(
    logits: torch.Tensor,
    row_starts: torch.Tensor,
    row_ends: torch.Tensor,
) -> torch.Tensor:
    num_rows = logits.size(0)
    out = torch.full((num_rows, TOPK), -1, dtype=torch.int32, device=logits.device)
    for i in range(num_rows):
        start = int(row_starts[i])
        end = int(row_ends[i])
        length = end - start
        if length <= 0:
            continue
        if length <= TOPK:
            out[i, :length] = torch.arange(length, dtype=torch.int32, device=logits.device)
        else:
            out[i] = torch.topk(
                logits[i, start:end], TOPK, largest=True, sorted=False
            ).indices.to(torch.int32)
    return out


def _ref_decode(logits: torch.Tensor, next_n: int, seq_lens: torch.Tensor) -> torch.Tensor:
    num_rows = logits.size(0)
    out = torch.full((num_rows, TOPK), -1, dtype=torch.int32, device=logits.device)
    for i in range(num_rows):
        row_end = int(seq_lens[i // next_n]) - next_n + (i % next_n) + 1
        if row_end <= 0:
            continue
        if row_end <= TOPK:
            out[i, :row_end] = torch.arange(row_end, dtype=torch.int32, device=logits.device)
        else:
            out[i] = torch.topk(
                logits[i, :row_end], TOPK, largest=True, sorted=False
            ).indices.to(torch.int32)
    return out


def _assert_index_sets_equal(
    logits_row: torch.Tensor,
    ref: torch.Tensor,
    got: torch.Tensor,
    length: int,
    row: int,
) -> None:
    valid = min(length, TOPK)
    got_valid = got[got >= 0]
    assert got_valid.numel() == valid, f"row={row}: expected {valid} indices, got {got_valid.numel()}"
    assert int(got_valid.min()) >= 0 and int(got_valid.max()) < length, (
        f"row={row}: index out of range"
    )
    ref_set = set(ref[ref >= 0].tolist())
    got_set = set(got_valid.tolist())
    more = got_set - ref_set
    less = ref_set - got_set
    if not more and not less:
        return
    more_vals = sorted(float(logits_row[i]) for i in more)
    less_vals = sorted(float(logits_row[i]) for i in less)
    assert more_vals == less_vals, (
        f"row={row}: index mismatch more={sorted(more)} less={sorted(less)}"
    )


def _gbps(nbytes: int, us: float) -> float:
    return nbytes / us / 1e3 if us and us > 0 else 0.0


def _torch_topk(logits: torch.Tensor) -> None:
    k = min(TOPK, logits.size(-1))
    torch.topk(logits, k, dim=-1, largest=True, sorted=False)


@torch.inference_mode()
def test_prefill(bs: int = 4, seq_len: int = 4096, return_values: bool = False) -> dict:
    torch.manual_seed(0)
    device = "cuda"
    logits = torch.randn(bs, seq_len, dtype=torch.float32, device=device)
    row_starts = torch.zeros(bs, dtype=torch.int32, device=device)
    row_ends = torch.full((bs,), seq_len, dtype=torch.int32, device=device)

    ref = _ref_prefill(logits, row_starts, row_ends)
    got, values = topk_per_row_prefill(
        logits, row_starts, row_ends, return_values=return_values
    )
    assert got.shape == (bs, TOPK)
    for i in range(bs):
        _assert_index_sets_equal(logits[i], ref[i], got[i], seq_len, i)
        if return_values:
            assert values is not None
            valid = min(seq_len, TOPK)
            gathered = logits[i].gather(0, got[i, :valid].long())
            torch.testing.assert_close(values[i, :valid], gathered, rtol=1e-5, atol=1e-5)

    _, aiter_us = run_perftest(
        topk_per_row_prefill,
        logits,
        row_starts,
        row_ends,
        return_values=return_values,
        num_iters=PERF_ITERS,
        num_warmup=PERF_WARMUP,
    )
    _, torch_us = run_perftest(
        _torch_topk,
        logits,
        num_iters=PERF_ITERS,
        num_warmup=PERF_WARMUP,
    )
    nbytes = bs * seq_len * 4 + bs * TOPK * 4 * (2 if return_values else 1)
    print(
        f"PASS prefill bs={bs} seq_len={seq_len} return_values={return_values} "
        f"aiter={aiter_us:.2f}us torch={torch_us:.2f}us"
    )
    return {
        "mode": "prefill",
        "num_rows": bs,
        "seq_len": seq_len,
        "next_n": 1,
        "values": return_values,
        "status": "PASS",
        "aiter_us": aiter_us,
        "torch_us": torch_us,
        "speedup": torch_us / aiter_us if aiter_us else None,
        "aiter_gbps": _gbps(nbytes, aiter_us),
        "torch_gbps": _gbps(nbytes, torch_us),
    }


@torch.inference_mode()
def test_prefill_short_rows(bs: int = 2, seq_len: int = 1024) -> dict:
    torch.manual_seed(1)
    device = "cuda"
    logits = torch.randn(bs, seq_len, dtype=torch.float32, device=device)
    row_starts = torch.zeros(bs, dtype=torch.int32, device=device)
    row_ends = torch.full((bs,), seq_len, dtype=torch.int32, device=device)

    got, _ = topk_per_row_prefill(logits, row_starts, row_ends)
    expected = torch.arange(seq_len, dtype=torch.int32, device=device)
    for i in range(bs):
        assert torch.equal(got[i, :seq_len], expected)
        assert torch.all(got[i, seq_len:] == -1)

    _, aiter_us = run_perftest(
        topk_per_row_prefill,
        logits,
        row_starts,
        row_ends,
        num_iters=PERF_ITERS,
        num_warmup=PERF_WARMUP,
    )
    _, torch_us = run_perftest(
        _torch_topk,
        logits,
        num_iters=PERF_ITERS,
        num_warmup=PERF_WARMUP,
    )
    nbytes = bs * seq_len * 4 + bs * TOPK * 4
    print(
        f"PASS prefill_short_rows bs={bs} seq_len={seq_len} "
        f"aiter={aiter_us:.2f}us torch={torch_us:.2f}us"
    )
    return {
        "mode": "prefill_short",
        "num_rows": bs,
        "seq_len": seq_len,
        "next_n": 1,
        "values": False,
        "status": "PASS",
        "aiter_us": aiter_us,
        "torch_us": torch_us,
        "speedup": torch_us / aiter_us if aiter_us else None,
        "aiter_gbps": _gbps(nbytes, aiter_us),
        "torch_gbps": _gbps(nbytes, torch_us),
    }


@torch.inference_mode()
def test_decode(batch: int = 2, next_n: int = 2, seq_len: int = 4096) -> dict:
    torch.manual_seed(2)
    device = "cuda"
    num_rows = batch * next_n
    logits = torch.randn(num_rows, seq_len, dtype=torch.float32, device=device)
    seq_lens = torch.full((batch,), seq_len, dtype=torch.int32, device=device)

    ref = _ref_decode(logits, next_n, seq_lens)
    got = topk_per_row_decode(logits, next_n, seq_lens)
    assert got.shape == (num_rows, TOPK)
    for i in range(num_rows):
        row_end = seq_len - next_n + (i % next_n) + 1
        _assert_index_sets_equal(logits[i, :row_end], ref[i], got[i], row_end, i)

    _, aiter_us = run_perftest(
        topk_per_row_decode,
        logits,
        next_n,
        seq_lens,
        num_iters=PERF_ITERS,
        num_warmup=PERF_WARMUP,
    )
    _, torch_us = run_perftest(
        _torch_topk,
        logits,
        num_iters=PERF_ITERS,
        num_warmup=PERF_WARMUP,
    )
    nbytes = num_rows * seq_len * 4 + num_rows * TOPK * 4
    print(
        f"PASS decode batch={batch} next_n={next_n} seq_len={seq_len} "
        f"aiter={aiter_us:.2f}us torch={torch_us:.2f}us"
    )
    return {
        "mode": "decode",
        "num_rows": num_rows,
        "seq_len": seq_len,
        "next_n": next_n,
        "values": False,
        "status": "PASS",
        "aiter_us": aiter_us,
        "torch_us": torch_us,
        "speedup": torch_us / aiter_us if aiter_us else None,
        "aiter_gbps": _gbps(nbytes, aiter_us),
        "torch_gbps": _gbps(nbytes, torch_us),
    }


def _print_summary(rows: list[dict]) -> None:
    df = pd.DataFrame(rows)
    for col in ("aiter_us", "torch_us", "speedup", "aiter_gbps", "torch_gbps"):
        df[col] = df[col].map(lambda x: f"{x:.2f}" if pd.notna(x) else "")
    print("\n" + "=" * 110)
    print("topk_per_row summary  (k=2048, speedup = torch_us / aiter_us)")
    print("=" * 110)
    print(df.to_string(index=False))
    print("=" * 110)


def main() -> int:
    rows = [
        test_prefill(return_values=False),
        test_prefill(return_values=True),
        test_prefill_short_rows(),
        test_decode(next_n=1),
        test_decode(next_n=2),
    ]
    _print_summary(rows)
    print("ALL PASSED")
    return 0


if __name__ == "__main__":
    sys.exit(main())
