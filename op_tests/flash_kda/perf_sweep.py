# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
"""FlashKDA HCU 接入验收：性能 sweep（对齐性能表的分组与计时口径）。

产出 CSV，供 ``perf_compare.py`` 与性能表 ``bw1000 同口径 ms`` 列逐行比对。
计时方式复用 ``bench_fwd.bench_fn``（warmup/iters/repeats + CUDA event，取 mean/min/max）。

用法：
    python op_tests/flash_kda/perf_sweep.py --out /tmp/kda_measured.csv
    python op_tests/flash_kda/perf_sweep.py --groups short_h6 --limit 2 --out /tmp/q.csv
"""
import argparse
import csv
import math

import torch
import torch.nn.functional as F

from op_tests.flash_kda.bench_fwd import bench_fn

D = 128
LOWER_BOUND = -5.0


LONG_TOKENS = (1024, 2048, 3072, 4096, 5120, 6144, 7168, 8192)
SHORT_BATCH_H6 = (1, 2, 4, 8, 16, 32, 48, 64, 96, 128, 192, 256, 384, 512, 768, 1024)
SHORT_BATCH_H96 = (1, 2, 4, 8, 16, 24, 32, 48, 64, 96, 128, 192, 256, 384, 512)
VARLEN_H96 = ((1300, 547, 2048, 963, 271, 3063), (1024,) * 8, (10, 20, 30, 500, 1000, 2001))
VARLEN_H6 = ((1024,) * 8, (1300, 547, 2048, 963, 271, 3063))


def build_inputs(batch, tokens, heads, seq_lens, seed):
    torch.manual_seed(seed)
    device = torch.device("cuda")
    scale = 1.0 / math.sqrt(D)
    n = batch if seq_lens is None else len(seq_lens)
    extra = {}
    if seq_lens is not None:
        extra["cu_seqlens"] = torch.tensor(
            [0] + torch.cumsum(torch.tensor(seq_lens), dim=0).tolist(),
            dtype=torch.long, device=device,
        )
    q = F.normalize(torch.randn((batch, tokens, heads, D), dtype=torch.float32, device=device),
                    p=2, dim=-1).to(torch.bfloat16)
    k = F.normalize(torch.randn((batch, tokens, heads, D), dtype=torch.float32, device=device),
                    p=2, dim=-1).to(torch.bfloat16)
    v = torch.randn((batch, tokens, heads, D), dtype=torch.bfloat16, device=device)
    g = torch.randn((batch, tokens, heads, D), dtype=torch.bfloat16, device=device)
    beta = torch.randn((batch, tokens, heads), dtype=torch.bfloat16, device=device)
    A_log = torch.rand(heads, dtype=torch.float32, device=device)
    dt_bias = torch.rand(heads, D, dtype=torch.float32, device=device)
    state_bf16 = torch.arange(n * heads * D * D, dtype=torch.float32, device=device)
    state_bf16 = state_bf16.reshape(n, heads, D, D).to(torch.bfloat16)
    return dict(q=q, k=k, v=v, g=g, beta=beta, A_log=A_log, dt_bias=dt_bias,
                scale=scale, state_bf16=state_bf16, extra=extra)


def time_variant(fn, warmup, iters, repeats):
    return bench_fn(fn, warmup, iters, repeats)


def run_one(group, batch, tokens, heads, seq_lens, args, writer, batch_label=None):
    from aiter.ops.flash_kda import fwd

    x = build_inputs(batch, tokens, heads, seq_lens, args.seed)
    out = torch.zeros_like(x["q"])
    st_bf16 = x["state_bf16"]
    fin_bf16 = torch.zeros_like(st_bf16)
    st_fp32 = st_bf16.float()
    fin_fp32 = torch.zeros_like(st_fp32)

    def call(init=None, fin=None):
        fwd(x["q"], x["k"], x["v"], x["g"], x["beta"], x["scale"], out,
            A_log=x["A_log"], dt_bias=x["dt_bias"], lower_bound=LOWER_BOUND,
            initial_state=init, final_state=fin, state_v_first=True, **x["extra"])

    variants = [
        ("bf16", 1, 1, lambda: call(st_bf16, fin_bf16)),
        ("none", 0, 0, lambda: call()),
        ("fp32", 1, 1, lambda: call(st_fp32, fin_fp32)),
        ("bf16", 1, 0, lambda: call(st_bf16, None)),
        ("fp32", 1, 0, lambda: call(st_fp32, None)),
        ("bf16", 0, 1, lambda: call(None, fin_bf16)),
        ("fp32", 0, 1, lambda: call(None, fin_fp32)),
    ]
    label = batch if batch_label is None else batch_label
    for state_dtype, has_in, has_out, fn in variants:
        mean, mn, mx = time_variant(fn, args.warmup, args.iters, args.repeats)
        writer.writerow([group, label, tokens, heads, D, state_dtype,
                         has_in, has_out, f"{mean:.4f}", f"{mn:.4f}", f"{mx:.4f}"])
        print(f"{group} B={label} T={tokens} H={heads} state={state_dtype} "
              f"in/out={has_in}/{has_out} mean={mean:.4f} ms")


def main():
    parser = argparse.ArgumentParser()
    parser.add_argument("--out", default="/tmp/kda_measured.csv")
    parser.add_argument("--groups", default="long_h96,long_h6,short_h6,short_h96,varlen")
    parser.add_argument("--limit", type=int, default=0, help="每组只跑前 N 个配置，0 为全部")
    parser.add_argument("--warmup", type=int, default=30)
    parser.add_argument("--iters", type=int, default=200)
    parser.add_argument("--repeats", type=int, default=5)
    parser.add_argument("--seed", type=int, default=42)
    parser.add_argument("--skip-special", action="store_true", help="跳过 1/0（HasStateOut=0）变体")
    args = parser.parse_args()

    def take(seq):
        return seq[: args.limit] if args.limit else seq

    with open(args.out, "w", newline="") as f:
        writer = csv.writer(f)
        writer.writerow(["group", "batch", "seq", "heads", "dim", "state_dtype",
                         "has_state_in", "has_state_out", "mean_ms", "min_ms", "max_ms"])
        groups = [g.strip() for g in args.groups.split(",") if g.strip()]
        for group in groups:
            if group == "long_h96":
                for t in take(LONG_TOKENS):
                    run_one(group, 1, t, 96, None, args, writer)
            elif group == "long_h6":
                for t in take(LONG_TOKENS):
                    run_one(group, 1, t, 6, None, args, writer)
            elif group == "short_h6":
                for b in take(SHORT_BATCH_H6):
                    run_one(group, b, 1, 6, None, args, writer)
            elif group == "short_h96":
                for b in take(SHORT_BATCH_H96):
                    run_one(group, b, 1, 96, None, args, writer)
            elif group == "varlen":
                for lens in take(VARLEN_H96):
                    run_one(group, 1, sum(lens), 96, lens, args, writer,
                            batch_label=len(lens))
                for lens in take(VARLEN_H6):
                    run_one(group, 1, sum(lens), 6, lens, args, writer,
                            batch_label=len(lens))
            else:
                raise SystemExit(f"unknown group: {group}")
    print(f"\nwritten: {args.out}")


if __name__ == "__main__":
    main()
