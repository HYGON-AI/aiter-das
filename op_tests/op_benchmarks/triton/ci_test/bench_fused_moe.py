#!/usr/bin/env python3
"""CI perf: fused_moe (shapes/quant from Triton HCU perf regression).

Writes fused_moe.csv under --out-dir / $AITER_CI_TEST_OUT.
"""
from __future__ import annotations

import argparse
from pathlib import Path

import torch
import triton

from bench_common import add_out_dir_arg, ensure_paths, out_dir, write_csv

ensure_paths()

from aiter.ops.triton.moe_op import fused_moe  # noqa: E402
from aiter.ops.triton.utils.types import torch_to_triton_dtype  # noqa: E402
from op_tests.triton_tests.test_moe import input_helper  # noqa: E402

# Same shapes / quant as scripts/hcu/perf_report.py
SHAPES = [
    (128, 256, 1024, 8, 2),
    (512, 256, 1024, 8, 2),
    (1024, 256, 7168, 8, 2),
]
QUANT_MODES = [
    {"quant_mode": "bf16", "dtype": "fp16", "int8_w8a16": False, "fp8_w8a8": False},
    {"quant_mode": "int8_w8a16", "dtype": "fp16", "int8_w8a16": True, "fp8_w8a8": False},
    {
        "quant_mode": "fp8_w8a8",
        "dtype": "fp16",
        "int8_w8a16": False,
        "fp8_w8a8": True,
        "block_shape": [128, 128],
    },
]

_DTYPE = {"fp16": torch.float16, "bf16": torch.bfloat16}


def run(out: Path) -> Path:
    headers = ["M", "N", "K", "E", "top_k", "dtype", "quant_mode", "time_ms"]
    rows = []
    for M, N, K, E, top_k in SHAPES:
        for q in QUANT_MODES:
            dtype = _DTYPE[q["dtype"]]
            block_shape = q.get("block_shape")
            (
                a,
                b,
                c,
                _,
                b_zp,
                a_scale,
                b_scale,
                topk_weights,
                topk_ids,
                sorted_token_ids,
                expert_ids,
                num_tokens_post_padded,
                config,
            ) = input_helper(
                M,
                N,
                K,
                top_k,
                E,
                routed_weight=False,
                dtype=dtype,
                fp8_w8a8=q["fp8_w8a8"],
                int8_w8a16=q["int8_w8a16"],
                int8_w8a8=False,
                block_shape=block_shape,
            )

            def _fn(
                a=a,
                b=b,
                c=c,
                a_scale=a_scale,
                b_scale=b_scale,
                b_zp=b_zp,
                topk_weights=topk_weights,
                topk_ids=topk_ids,
                sorted_token_ids=sorted_token_ids,
                expert_ids=expert_ids,
                num_tokens_post_padded=num_tokens_post_padded,
                top_k=top_k,
                dtype=dtype,
                config=config,
                q=q,
                block_shape=block_shape,
            ):
                return fused_moe(
                    a,
                    b,
                    c,
                    a_scale,
                    b_scale,
                    b_zp,
                    topk_weights,
                    topk_ids,
                    sorted_token_ids,
                    None,  # sorted_weights
                    expert_ids,
                    num_tokens_post_padded,
                    False,  # mul_routed_weight
                    top_k,
                    torch_to_triton_dtype[dtype],
                    use_fp8_w8a8=q["fp8_w8a8"],
                    use_int8_w8a16=q["int8_w8a16"],
                    block_shape=block_shape,
                    config=config,
                )

            ms = triton.testing.do_bench(_fn, warmup=25, rep=100)
            rows.append(
                [M, N, K, E, top_k, q["dtype"], q["quant_mode"], f"{ms:.6f}"]
            )
            print(
                f"moe M={M} N={N} K={K} E={E} topk={top_k} {q['quant_mode']}: {ms:.3f} ms"
            )
    return write_csv(out / "fused_moe.csv", headers, rows)


def main() -> int:
    p = argparse.ArgumentParser(description=__doc__)
    add_out_dir_arg(p)
    args = p.parse_args()
    run(out_dir(args.out_dir))
    return 0


if __name__ == "__main__":
    raise SystemExit(main())
