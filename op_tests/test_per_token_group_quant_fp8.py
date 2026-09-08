#!/usr/bin/env python3
# SPDX-License-Identifier: MIT
"""Correctness and benchmark tests for aiter HIP per_token_group_quant_fp8."""

import argparse
import time

import pytest
import torch

import aiter

# num_tokens x hidden_size x group_size
# group_size must be power-of-2, >=16, and divide hidden_size.
BENCH_SHAPES_QUICK = [
    "4096x7168x128",
    "65536x128x128",
]

BENCH_SHAPES_DEFAULT = [
    "128x7168x128",
    "512x4096x128",
    "4096x4096x128",
    "4096x7168x128",
    "4096x8192x128",
    "8192x7168x128",
    "4096x7168x64",
    "4096x4096x256",
    "4096x8192x256", 
    "65536x128x128",
    "65536x7168x128",
    "131072x128x128",
    "2048x4096x1024",
    "1024x8192x512",
]

BENCH_SHAPE_SUITES = {
    "quick": BENCH_SHAPES_QUICK,
    "default": BENCH_SHAPES_DEFAULT,
    "full": BENCH_SHAPES_DEFAULT,
}


def native_per_token_group_quant_fp8(
    x: torch.Tensor,
    group_size: int,
    eps: float = 1e-5,
    dtype: torch.dtype = torch.float8_e4m3fn,
    use_ue8m0: bool = False,
) -> tuple[torch.Tensor, torch.Tensor]:
    assert x.shape[-1] % group_size == 0
    assert x.is_contiguous()

    finfo = torch.finfo(dtype)
    x_ = x.reshape(x.numel() // group_size, group_size)
    amax = x_.abs().max(dim=-1, keepdim=True)[0].clamp(min=eps).to(torch.float32)
    scale = amax / finfo.max
    if use_ue8m0:
        scale = torch.pow(2.0, torch.ceil(torch.log2(scale.clamp(min=eps))))
    x_q = (x_ / scale).clamp(min=finfo.min, max=finfo.max).to(dtype)
    return x_q.reshape(x.shape), scale.reshape(x.shape[:-1] + (x.shape[-1] // group_size,))


def alloc_outputs(x: torch.Tensor, group_size: int) -> tuple[torch.Tensor, torch.Tensor]:
    out_q = torch.empty(x.shape, dtype=torch.float8_e4m3fn, device=x.device)
    out_s = torch.empty(
        x.shape[:-1] + (x.shape[-1] // group_size,),
        dtype=torch.float32,
        device=x.device,
    )
    return out_q, out_s


def run_aiter_cu(
    x: torch.Tensor,
    group_size: int,
    eps: float,
    use_ue8m0: bool,
    out_q: torch.Tensor | None = None,
    out_s: torch.Tensor | None = None,
) -> tuple[torch.Tensor, torch.Tensor]:
    if out_q is None or out_s is None:
        out_q, out_s = alloc_outputs(x, group_size)
    aiter.per_token_group_quant_fp8(out_q, x, out_s, group_size, eps, use_ue8m0)
    return out_q, out_s


def verify_against_ref(
    ref_q: torch.Tensor,
    ref_s: torch.Tensor,
    q: torch.Tensor,
    s: torch.Tensor,
    use_ue8m0: bool = False,
) -> tuple[str, str, float]:
    atol = 1e-4 if use_ue8m0 else 1e-5
    scale_ok = torch.allclose(ref_s, s, atol=atol, rtol=atol)
    q_diff = (q.view(torch.int8).float() - ref_q.view(torch.int8).float()).abs().max().item()
    q_mark = "OK" if q_diff <= 1.0 else f"NG({q_diff:.0f})"
    s_mark = "OK" if scale_ok else "NG"
    return q_mark, s_mark, q_diff


def assert_close_to_native(
    native_q: torch.Tensor,
    native_s: torch.Tensor,
    cu_q: torch.Tensor,
    cu_s: torch.Tensor,
    use_ue8m0: bool,
) -> None:
    q_mark, s_mark, q_diff = verify_against_ref(native_q, native_s, cu_q, cu_s, use_ue8m0)
    assert s_mark == "OK", "scale mismatch vs native reference"
    assert q_mark == "OK", f"FP8 max int8 diff {q_diff} > 1"


def bench_us(fn, warmup: int, iters: int) -> float:
    for _ in range(warmup):
        fn()
    torch.cuda.synchronize()

    start = time.perf_counter()
    for _ in range(iters):
        fn()
    torch.cuda.synchronize()
    return (time.perf_counter() - start) * 1e6 / iters


def run_correctness_case(
    num_tokens: int,
    hidden_size: int,
    group_size: int,
    dtype: torch.dtype,
    eps: float,
    use_ue8m0: bool,
) -> None:
    x = torch.randn(num_tokens, hidden_size, dtype=dtype, device="cuda")
    native_q, native_s = native_per_token_group_quant_fp8(
        x, group_size, eps=eps, use_ue8m0=use_ue8m0
    )
    cu_q, cu_s = run_aiter_cu(x, group_size, eps=eps, use_ue8m0=use_ue8m0)
    assert_close_to_native(native_q, native_s, cu_q, cu_s, use_ue8m0)


def run_bench_case(
    num_tokens: int,
    hidden_size: int,
    group_size: int,
    dtype: torch.dtype,
    eps: float,
    use_ue8m0: bool,
    warmup: int,
    iters: int,
) -> dict:
    x = torch.randn(num_tokens, hidden_size, dtype=dtype, device="cuda")
    out_q, out_s = alloc_outputs(x, group_size)

    run_aiter_cu(x, group_size, eps, use_ue8m0, out_q, out_s)
    ref_q, ref_s = native_per_token_group_quant_fp8(x, group_size, eps=eps, use_ue8m0=use_ue8m0)
    assert_close_to_native(ref_q, ref_s, out_q, out_s, use_ue8m0)
    q_mark, s_mark, _ = verify_against_ref(ref_q, ref_s, out_q, out_s, use_ue8m0)

    cu_us = bench_us(
        lambda: run_aiter_cu(x, group_size, eps, use_ue8m0, out_q, out_s),
        warmup,
        iters,
    )

    return {
        "q_mark": q_mark,
        "s_mark": s_mark,
        "cu_us": cu_us,
    }


def run_benchmark(
    shapes: list[str],
    dtype: torch.dtype,
    eps: float,
    use_ue8m0: bool,
    warmup: int,
    iters: int,
) -> None:
    shape_width = max(len(shape) for shape in shapes)
    shape_width = max(shape_width, len("shape"))

    header = f"{'shape':<{shape_width}} | {'Q':<4} | {'S':<4} | {'aiter (us)':<12}"
    print("=" * len(header))
    print(header)
    print("-" * len(header))

    for shape in shapes:
        num_tokens, hidden_size, group_size = map(int, shape.lower().split("x"))
        result = run_bench_case(
            num_tokens, hidden_size, group_size, dtype, eps, use_ue8m0, warmup, iters
        )
        line = (
            f"{shape:<{shape_width}} | {result['q_mark']:<4} | {result['s_mark']:<4} | "
            f"{result['cu_us']:<12.2f}"
        )
        print(line)

    print("=" * len(header))
    print(f"Ran {len(shapes)} shape(s), dtype={dtype}, use_ue8m0={use_ue8m0}")
    print("Notes:")
    print("- aiter times in-place kernel calls with pre-allocated buffers")


@pytest.mark.parametrize("num_tokens", [128, 4096])
@pytest.mark.parametrize("hidden_size,group_size", [(128, 128), (7168, 128)])
@pytest.mark.parametrize("dtype", [torch.bfloat16, torch.float16])
@pytest.mark.parametrize("use_ue8m0", [False, True])
def test_per_token_group_quant_fp8_cu(
    num_tokens: int,
    hidden_size: int,
    group_size: int,
    dtype: torch.dtype,
    use_ue8m0: bool,
):
    run_correctness_case(num_tokens, hidden_size, group_size, dtype, 1e-5, use_ue8m0)


def main():
    parser = argparse.ArgumentParser(
        description="Correctness and benchmark for per_token_group_quant_fp8"
    )
    parser.add_argument(
        "--suite",
        choices=sorted(BENCH_SHAPE_SUITES.keys()),
        default="default",
        help="Predefined shape suite (ignored if --shapes is set)",
    )
    parser.add_argument(
        "--shapes",
        nargs="+",
        default=None,
        help="Shapes as num_tokens x hidden_size x group_size",
    )
    parser.add_argument("--dtype", choices=["bf16", "fp16"], default="bf16")
    parser.add_argument("--eps", type=float, default=1e-5)
    parser.add_argument("--use-ue8m0", action="store_true")
    parser.add_argument("--warmup", type=int, default=10)
    parser.add_argument("--iters", type=int, default=100)
    args = parser.parse_args()

    dtype = torch.bfloat16 if args.dtype == "bf16" else torch.float16

    shapes = args.shapes if args.shapes is not None else BENCH_SHAPE_SUITES[args.suite]
    run_benchmark(shapes, dtype, args.eps, args.use_ue8m0, args.warmup, args.iters)


if __name__ == "__main__":
    main()
