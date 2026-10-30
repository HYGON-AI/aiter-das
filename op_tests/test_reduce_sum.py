# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
"""Correctness + bandwidth / W-tune for aiter.reduce_sum."""

import argparse
import os
from typing import Optional

import pandas as pd
import torch

import aiter
from aiter import dtypes
from aiter.test_common import benchmark, checkAllclose, run_perftest


def _on_perf_model() -> bool:
    """PerfModel: torch profiler often yields empty device rows → us=0."""
    return os.getenv("GPU_CHIP", "").strip().lower() in {"nmz", "sb", "bw"}


def _detect_arch() -> str:
    """Mirror csrc detect_reduce_sum_arch (GPU_ARCHS / GPU_CHIP first)."""
    archs = os.getenv("GPU_ARCHS", "").strip().lower()
    if "gfx946" in archs:
        return "gfx946"
    if "gfx938" in archs or "gfx936" in archs:
        return "gfx938"
    chip = os.getenv("GPU_CHIP", "").strip().lower()
    if chip == "sb":
        return "gfx946"
    if chip in {"nmz", "bw"}:
        return "gfx938"
    return "gfx938"


FULL_BATCH = [
    1024,
    2048,
    4096,
    8192,
    16384,
    32768,
    65536,
    131072,
    262144,
    524288,
]
FULL_DIM = [1024, 2048, 4096]
W_CANDIDATES = [1, 2, 4, 8, 16]


def pick_waves_per_block(
    batch: int, dim: int, override_w: int = -1, arch: Optional[str] = None
) -> int:
    """Mirror of csrc pick_waves_per_block_gfx938 / _gfx946."""
    if override_w > 0:
        return override_w
    arch = arch or _detect_arch()
    if arch == "gfx946":
        # Provisional — replace after overnight tune.
        if dim <= 1024:
            w = 8 if batch >= 65536 else 4
        elif dim <= 2048:
            w = 8 if batch >= 131072 else 4
        else:
            w = 4 if batch >= 131072 else 2
    else:
        if dim <= 1024:
            w = 4
        elif dim <= 2048:
            w = 8 if batch >= 131072 else 2
        else:
            w = 1
    return max(1, min(w, batch))


def torch_reduce_sum(input: torch.Tensor) -> torch.Tensor:
    return input.float().sum(dim=-1).to(dtype=input.dtype)


def bench_event_us(fn, warmup=10, iters=50):
    """Lightweight timing without L2-rotate copies (needed for large B)."""
    for _ in range(warmup):
        fn()
    torch.cuda.synchronize()
    start = torch.cuda.Event(enable_timing=True)
    end = torch.cuda.Event(enable_timing=True)
    start.record()
    for _ in range(iters):
        fn()
    end.record()
    end.synchronize()
    return start.elapsed_time(end) * 1000.0 / iters  # us


@benchmark()
def test_reduce_sum(batch, dim, dtype, waves_per_block=-1, check=True):
    ret = {}
    input = torch.randn(batch, dim, dtype=dtype, device="cuda")
    out = torch.empty(batch, dtype=dtype, device="cuda")

    if check:
        ref = torch_reduce_sum(input)
        aiter.reduce_sum(out, input, waves_per_block)
        err = checkAllclose(ref.float(), out.float(), rtol=1e-2, atol=1e-2)
    else:
        err = 0

    bytes_moved = input.nbytes + out.nbytes
    # Large tensors: Event timing to avoid rotate OOM / huge deepcopy.
    # PerfModel: run_perftest/profiler post-process often has no CUDA rows → us=0.
    if _on_perf_model() or batch * dim * input.element_size() > 64 * 1024 * 1024:
        # Fewer iters on PMD: each launch is simulated and can be very slow.
        warmup, iters = (2, 5) if _on_perf_model() else (10, 50)
        us = bench_event_us(
            lambda: aiter.reduce_sum(out, input, waves_per_block),
            warmup=warmup,
            iters=iters,
        )
    else:
        _, us = run_perftest(
            aiter.reduce_sum,
            out,
            input,
            waves_per_block,
            num_iters=51,
            num_warmup=5,
        )

    arch = _detect_arch()
    ret["arch"] = arch
    ret["us"] = us
    ret["TB/s"] = bytes_moved / us / 1e6 if us > 0 else 0.0
    ret["err"] = err
    ret["W"] = pick_waves_per_block(batch, dim, waves_per_block, arch)
    return ret


def tune_waves(batch, dim, dtype):
    """Sweep W candidates; return best row + all rows."""
    input = torch.randn(batch, dim, dtype=dtype, device="cuda")
    out = torch.empty(batch, dtype=dtype, device="cuda")
    # Correctness once with auto W.
    ref = torch_reduce_sum(input)
    aiter.reduce_sum(out, input, -1)
    err = checkAllclose(ref.float(), out.float(), rtol=1e-2, atol=1e-2)

    bytes_moved = input.nbytes + out.nbytes
    rows = []
    for w in W_CANDIDATES:
        us = bench_event_us(lambda w=w: aiter.reduce_sum(out, input, w))
        rows.append(
            {
                "batch": batch,
                "dim": dim,
                "dtype": str(dtype).replace("torch.", ""),
                "W": w,
                "us": us,
                "TB/s": bytes_moved / us / 1e6 if us > 0 else 0.0,
                "err": err,
            }
        )
    best = min(rows, key=lambda r: r["us"])
    return best, rows


l_dtype = ["bf16"]
l_batch = list(FULL_BATCH)
l_dim = list(FULL_DIM)

parser = argparse.ArgumentParser(
    formatter_class=argparse.RawTextHelpFormatter,
    description="test / tune aiter.reduce_sum",
)
parser.add_argument(
    "-d",
    "--dtype",
    type=str,
    choices=["fp16", "bf16", "fp32"],
    nargs="*",
    default=None,
    help="Data type(s), e.g. -d bf16 fp16",
)
parser.add_argument(
    "-b",
    "--batch",
    type=int,
    nargs="*",
    default=None,
    help="Batch size(s), e.g. -b 1024 524288",
)
parser.add_argument(
    "-n",
    "--dim",
    type=int,
    nargs="*",
    default=None,
    help="Reduce dim(s), e.g. -n 1024 4096",
)
parser.add_argument(
    "-w",
    "--waves_per_block",
    type=int,
    default=-1,
    help="Override waves/block (-1=auto)",
)
parser.add_argument(
    "--tune",
    action="store_true",
    help="Sweep W in {1,2,4,8,16} and report best per (B,D)",
)
parser.add_argument(
    "--no-check",
    action="store_true",
    help="Skip correctness check (perf only)",
)
parser.add_argument(
    "--csv",
    type=str,
    default=None,
    help="Optional path to write results CSV",
)
args = parser.parse_args()

if args.dtype is None:
    l_dtype = [dtypes.d_dtypes[key] for key in l_dtype]
else:
    l_dtype = [dtypes.d_dtypes[d] for d in args.dtype]
if args.batch is not None:
    l_batch = args.batch
if args.dim is not None:
    l_dim = args.dim

if args.tune:
    all_rows = []
    best_rows = []
    for dtype in l_dtype:
        for batch in l_batch:
            for dim in l_dim:
                aiter.logger.info(f"tune B={batch} D={dim} dtype={dtype}")
                best, rows = tune_waves(batch, dim, dtype)
                all_rows.extend(rows)
                best_rows.append(best)
                aiter.logger.info(
                    f"  best W={best['W']} us={best['us']:.3f} TB/s={best['TB/s']:.3f}"
                )
    df_all = pd.DataFrame(all_rows)
    df_best = pd.DataFrame(best_rows)
    aiter.logger.info(f"reduce_sum tune ALL:\n{df_all.to_string()}")
    aiter.logger.info(f"reduce_sum tune BEST:\n{df_best.to_string()}")
    if args.csv:
        df_all.to_csv(args.csv, index=False)
        df_best.to_csv(args.csv.replace(".csv", "_best.csv"), index=False)
        aiter.logger.info(f"wrote {args.csv} and best csv")
else:
    df = []
    for dtype in l_dtype:
        for batch in l_batch:
            for dim in l_dim:
                ret = test_reduce_sum(
                    batch,
                    dim,
                    dtype,
                    args.waves_per_block,
                    check=not args.no_check,
                )
                df.append(ret)
    df = pd.DataFrame(df)
    aiter.logger.info(f"reduce_sum summary:\n{df.to_string()}")
    if args.csv:
        df.to_csv(args.csv, index=False)
