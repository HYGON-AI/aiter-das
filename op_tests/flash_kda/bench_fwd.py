# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
"""沿用官方 FlashKDA 的输入与计时方式，仅将调用入口适配到 AITER。

对照：https://github.com/MoonshotAI/FlashKDA/blob/d7e3b3a9f448500630fa60fb5200f4f9c9b1fc72/benchmarks/bench_fwd.py
只测 FlashKDA，不运行官方脚本中的 FLA/GDN 对照。正确性由 pytest 单独验收。
"""

import argparse
import math

import torch
import torch.nn.functional as F

from aiter.ops.flash_kda import fwd


def bench_fn(fn, warmup, iters, repeats):
    for _ in range(max(warmup, 1)):
        fn()
    torch.cuda.synchronize()

    all_ms = []
    for _ in range(repeats):
        torch.cuda.synchronize()
        starts = [torch.cuda.Event(enable_timing=True) for _ in range(iters)]
        ends = [torch.cuda.Event(enable_timing=True) for _ in range(iters)]
        for i in range(iters):
            starts[i].record()
            fn()
            ends[i].record()
        torch.cuda.synchronize()
        all_ms.extend([s.elapsed_time(e) for s, e in zip(starts, ends)])

    xs = sorted(float(x) for x in all_ms)
    n = len(xs)
    mean = sum(xs) / n if n else float("nan")
    mn = xs[0] if xs else float("nan")
    mx = xs[-1] if xs else float("nan")
    return mean, mn, mx


def run_case(B, T, H, D, warmup, iters, repeats, seed, seq_lens=None):
    # 每组重置 seed，输入不随 case 执行顺序变化。
    torch.manual_seed(seed)
    device = torch.device("cuda")
    lower_bound = -5.0
    scale = 1.0 / math.sqrt(D)
    N = B if seq_lens is None else len(seq_lens)

    extra = {}
    if seq_lens is not None:
        extra["cu_seqlens"] = torch.tensor(
            [0] + list(torch.cumsum(torch.tensor(seq_lens), dim=0).tolist()),
            dtype=torch.long, device=device,
        )
    print(f"shape=[{B},{T},{H},{D}] seq_lens={seq_lens} "
          f"warmup={warmup} iters={iters} repeats={repeats}")

    q = F.normalize(torch.randn((B, T, H, D), dtype=torch.float32, device=device),
                    p=2, dim=-1).to(torch.bfloat16)
    k = F.normalize(torch.randn((B, T, H, D), dtype=torch.float32, device=device),
                    p=2, dim=-1).to(torch.bfloat16)
    v = torch.randn((B, T, H, D), dtype=torch.bfloat16, device=device)
    g = torch.randn((B, T, H, D), dtype=torch.bfloat16, device=device)
    beta = torch.randn((B, T, H), dtype=torch.bfloat16, device=device)
    A_log = torch.rand(H, dtype=torch.float32, device=device)
    dt_bias = torch.rand(H, D, dtype=torch.float32, device=device)

    # 官方使用 VK 状态；FP32 初态从已量化的 BF16 初态提升。
    initial_state = torch.arange(N * H * D * D, dtype=torch.float32, device=device)
    initial_state = initial_state.reshape(N, H, D, D).to(torch.bfloat16)
    final_state = torch.zeros_like(initial_state)
    out = torch.zeros_like(q)

    def run_bf16():
        fwd(q, k, v, g, beta, scale, out,
            A_log=A_log, dt_bias=dt_bias, lower_bound=lower_bound,
            initial_state=initial_state, final_state=final_state,
            state_v_first=True, **extra)

    mean, mn, mx = bench_fn(run_bf16, warmup, iters, repeats)
    print(f"  fwd (bf16 state) : mean={mean:.4f} ms, min={mn:.4f} ms, max={mx:.4f} ms")

    def run_no_state():
        fwd(q, k, v, g, beta, scale, out,
            A_log=A_log, dt_bias=dt_bias, lower_bound=lower_bound,
            state_v_first=True, **extra)

    mean, mn, mx = bench_fn(run_no_state, warmup, iters, repeats)
    print(f"  fwd (no state)   : mean={mean:.4f} ms, min={mn:.4f} ms, max={mx:.4f} ms")

    initial_state_fp32 = initial_state.float()
    final_state_fp32 = torch.zeros_like(initial_state_fp32)

    def run_fp32():
        fwd(q, k, v, g, beta, scale, out,
            A_log=A_log, dt_bias=dt_bias, lower_bound=lower_bound,
            initial_state=initial_state_fp32, final_state=final_state_fp32,
            state_v_first=True, **extra)

    mean, mn, mx = bench_fn(run_fp32, warmup, iters, repeats)
    print(f"  fwd (fp32 state) : mean={mean:.4f} ms, min={mn:.4f} ms, max={mx:.4f} ms")


FIXED_CASES = [[8192]]
VARLEN_CASES = [[1300, 547, 2048, 963, 271, 3063], [1024] * 8]


def _positive_ints(text):
    try:
        values = tuple(int(v) for v in text.split(","))
    except ValueError as error:
        raise argparse.ArgumentTypeError("expected comma-separated positive integers") from error
    if any(v <= 0 for v in values):
        raise argparse.ArgumentTypeError("all values must be positive")
    return values


def _shape(text):
    values = _positive_ints(text)
    if len(values) != 3:
        raise argparse.ArgumentTypeError("--shape requires B,T,H")
    return values


def main():
    parser = argparse.ArgumentParser(description="FlashKDA 官方方式性能计时")
    parser.add_argument("--warmup", type=int, default=30)
    parser.add_argument("--iters", type=int, default=200)
    parser.add_argument("--repeats", type=int, default=5)
    parser.add_argument("--mode", choices=["fixed", "varlen", "all"], default=None,
                        help="选择默认用例，缺省 all；不能与 --shape/--lengths 混用")
    parser.add_argument("--shape", type=_shape, action="append", help="定长 B,T,H，可重复")
    parser.add_argument("--lengths", type=_positive_ints, action="append",
                        help="packed 序列长度，以逗号分隔，可重复；物理 B=1")
    parser.add_argument("--H", type=int, default=96, help="默认用例及 --lengths 的 head 数")
    parser.add_argument("--D", type=int, choices=[128], default=128)
    parser.add_argument("--seed", type=int, default=42)
    args = parser.parse_args()

    if args.H <= 0:
        parser.error("--H must be positive")
    if args.mode and (args.shape or args.lengths):
        parser.error("--mode selects default cases; use --shape/--lengths without --mode")
    cases = [(shape, None) for shape in (args.shape or [])]
    cases.extend(((1, sum(lengths), args.H), lengths) for lengths in (args.lengths or []))
    if not cases:
        if args.mode in (None, "fixed", "all"):
            cases.extend(((1, lengths[0], args.H), None) for lengths in FIXED_CASES)
        if args.mode in (None, "varlen", "all"):
            cases.extend(((1, sum(lengths), args.H), lengths) for lengths in VARLEN_CASES)
    print(f"seed={args.seed}")
    for (B, T, H), seq_lens in cases:
        run_case(B, T, H, args.D, args.warmup, args.iters, args.repeats, args.seed,
                 seq_lens=seq_lens)


if __name__ == "__main__":
    main()
