# SPDX-License-Identifier: MIT

import torch
import triton

import aiter
from aiter.ops.triton.quant import dynamic_per_token_quant_fp8_i8
from aiter.ops.triton.utils.arch_info import get_fp8_e4m3_dtype


TENCENT_AD_SHAPES = [
    (112, 1232),
    (2800, 1232),
    (4480, 1232),
    (8960, 1232),
    (11424, 1232),
    (13104, 1232),
    (28672, 1232),
    (57344, 1232),
    (8960, 1536),
    (28672, 1536),
    (57344, 1536),
]

N128_SHAPES = [
    (256, 128),
    (1024, 128),
    (4096, 128),
    (28672, 128),
]


def bench_shape(rows: int, cols: int) -> tuple[float, float]:
    x = torch.randn((rows, cols), dtype=torch.float16, device="cuda")
    quant_dtype = get_fp8_e4m3_dtype()
    qx = torch.empty_like(x, dtype=quant_dtype)
    scale = torch.empty((rows, 1), dtype=torch.float32, device=x.device)

    triton_fn = lambda: dynamic_per_token_quant_fp8_i8(qx, x, scale)
    hip_fn = lambda: aiter.dynamic_per_token_scaled_quant(qx, x, scale)

    # Compile/JIT both paths before timing. do_bench then reports GPU execution
    # time through events; it does not use xcu or a profiler-side duration.
    triton_fn()
    hip_fn()
    torch.cuda.synchronize()

    triton_ms = triton.testing.do_bench(triton_fn, warmup=100, rep=500)
    hip_ms = triton.testing.do_bench(hip_fn, warmup=100, rep=500)
    return triton_ms * 1000.0, hip_ms * 1000.0


if __name__ == "__main__":
    print("M,N,Triton_us,HIP_us,Triton_vs_HIP")
    for m, n in TENCENT_AD_SHAPES + N128_SHAPES:
        triton_us, hip_us = bench_shape(m, n)
        print(f"{m},{n},{triton_us:.3f},{hip_us:.3f},{hip_us / triton_us:.3f}x")
