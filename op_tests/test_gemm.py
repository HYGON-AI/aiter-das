# SPDX-License-Identifier: MIT
import torch
import torch.nn.functional as F
import sys
import os
import statistics
from aiter import dtypes
from aiter.test_common import checkAllclose, perftest

if 1:
    _path = os.path.abspath(os.path.dirname(__file__))
    sys.path.insert(0, f"{_path}/../../")
    from aiter.tuned_gemm import tgemm


def torch_mm(x, weight, bias=None, otype=None, scaleA=None, scaleB=None):
    if x.dtype == dtypes.i8:
        assert scaleA is None and scaleB is None
        assert otype == dtypes.i32
        try:
            out = torch._int_mm(x, weight.t())
        except RuntimeError:
            if x.shape[0] > 16:
                raise
            out = F.linear(x.to(dtypes.fp32), weight.to(dtypes.fp32)).to(otype)
        return out + bias if bias is not None else out
    if x.dtype == dtypes.fp8:
        if scaleA is None:
            scaleA = torch.ones(1, dtype=dtypes.fp32, device=x.device)
        if scaleB is None:
            scaleB = torch.ones(1, dtype=dtypes.fp32, device=x.device)

        try:
            out = torch._scaled_mm(
                x,
                weight.t(),
                out_dtype=otype,
                scale_a=scaleA,
                scale_b=scaleB,
                bias=bias,
            )
        except RuntimeError:
            out = F.linear(x.to(dtypes.fp32), weight.to(dtypes.fp32)) * scaleA * scaleB
            out = (out.to(otype) + bias) if bias is not None else out.to(otype)
        return out
    if scaleA is not None:
        x = x * scaleA
    if scaleB is not None:
        weight = weight * scaleB
    return F.linear(x, weight, bias).to(otype)


@perftest()
def run_torch(x, weight, bias=None, otype=None, scaleA=None, scaleB=None):
    return torch_mm(x, weight, bias, otype, scaleA, scaleB)


def gemm_b(x, weight, bias=None, otype=None, scaleA=None, scaleB=None):
    return tgemm.mm(x, weight, bias, otype, scaleA, scaleB)


@perftest()
def run_gemm_b(x, weight, bias=None, otype=None, scaleA=None, scaleB=None):
    return gemm_b(x, weight, bias, otype, scaleA, scaleB)


def percentile(values, q):
    values = sorted(values)
    pos = (len(values) - 1) * q
    lo = int(pos)
    hi = min(lo + 1, len(values) - 1)
    frac = pos - lo
    return values[lo] * (1.0 - frac) + values[hi] * frac


def paired_benchmark(torch_call, tuned_call, pair_iters=31, rounds=3):
    flush = torch.ones(8 * 1024 * 1024, dtype=torch.float32, device="cuda")
    start = torch.cuda.Event(enable_timing=True)
    end = torch.cuda.Event(enable_timing=True)
    times = {"torch": [], "tuned": []}

    def elapsed_us(call):
        start.record()
        out = call()
        end.record()
        end.synchronize()
        return out, start.elapsed_time(end) * 1000.0

    for _ in range(5):
        torch_call()
        tuned_call()
    torch.cuda.synchronize()

    outputs = {}
    for round_index in range(rounds):
        for pair_index in range(pair_iters):
            torch_first = (round_index + pair_index) % 2 == 0
            calls = (
                (("torch", torch_call), ("tuned", tuned_call))
                if torch_first
                else (("tuned", tuned_call), ("torch", torch_call))
            )
            for name, call in calls:
                flush.add_(1)
                outputs[name], us = elapsed_us(call)
                times[name].append(us)

    return (
        outputs["torch"],
        outputs["tuned"],
        statistics.median(times["torch"]),
        statistics.median(times["tuned"]),
        percentile(times["torch"], 0.90),
        percentile(times["tuned"], 0.90),
    )


def test_gemm(dtype, m, n, k, bias=False, otype=None, scaleA=None, scaleB=None):
    dim = (m, n, k)
    if dtype == dtypes.i8:
        assert otype == dtypes.i32
        x = torch.randint(-3, 4, (m, k), dtype=dtype, device="cuda")
        weight = torch.randint(-3, 4, (n, k), dtype=dtype, device="cuda")
    else:
        x = torch.randn(m, k, dtype=otype, device="cuda").to(dtype)
        weight = torch.rand(n, k, dtype=otype, device="cuda").to(dtype)
    if bias:
        bias = torch.rand(n, dtype=otype, device="cuda")
    else:
        bias = None
    if scaleA is not None:
        scaleA = torch.tensor(scaleA, dtype=dtypes.fp32, device="cuda")
    if scaleB is not None:
        scaleB = torch.tensor(scaleB, dtype=dtypes.fp32, device="cuda")
    torch_call = lambda: torch_mm(x, weight, bias, otype, scaleA, scaleB)
    tuned_call = lambda: gemm_b(x, weight, bias, otype, scaleA, scaleB)
    a, b, med_a, med_b, p90_a, p90_b = paired_benchmark(torch_call, tuned_call)

    msg = (
        f"[perf] dim: {str(dim):<20} dtype: {dtype}, "
        f"torch median: {med_a:<8.2f} us, B median: {med_b:<8.2f} us, "
        f"uplift: {med_a/med_b-1:<5.1%}, torch p90: {p90_a:<8.2f} us, "
        f"B p90: {p90_b:<8.2f} us, p90 uplift: {p90_a/p90_b-1:<5.1%}"
    )
    checkAllclose(a, b, msg=msg)


# test_gemm(
#     dtypes.fp8, 128, 768, 4096, bias=False, otype=dtypes.bf16, scaleA=0.5, scaleB=0.5
# )
# test_gemm(dtypes.bf16, 128, 32, 8192)
for dtype in [dtypes.fp8, dtypes.bf16]:
    # # qkv_proj
    for (m, n, k) in [(4096, 1280, 8192),
                      (128, 1280, 8192),
                      (128, 1024, 8192),
                      (128, 128, 8192),
                      ]:
        test_gemm(dtype, m, n, k, otype=dtypes.bf16)
    # # attn_out
    for (m, n, k) in [(4096, 8192, 1024),
                      (128, 8192, 1024)]:
        test_gemm(dtype, m, n, k, otype=dtypes.bf16)
    test_gemm(dtype, 128, 1024, 8192, otype=dtypes.bf16)
    test_gemm(dtype, 128, 32, 8192, otype=dtypes.bf16)
    # # gating
    for (m, n, k) in [(4096, 32, 8192),
                      (128, 32, 8192)]:
        test_gemm(dtype, m, n, k, otype=dtypes.bf16)
    # # gating
    for (m, n, k) in [(1, 19392, 8192),
                      (128, 19392, 8192)]:
        test_gemm(dtype, m, n, k, otype=dtypes.bf16)
