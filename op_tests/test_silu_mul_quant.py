# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
# SPDX-License-Identifier: MIT
#
# Correctness + perf tests for the fused silu_mul quant family:
#   fuse_silu_mul_quant / fuse_silu_mul_fp8_quant          (2D, int8 / fp8)
#   fuse_silu_mul_quant_ep / fuse_silu_mul_fp8_quant_ep    (3D EP, int8 / fp8)
#   fuse_silu_and_mul_ep                                   (3D EP, no quant)
#   fuse_silu_mul_per_token_quant                          (generic entry)
#   relu2
#
# Usage:
#   python test_silu_mul_quant.py                  # correctness suite + perf
#   python test_silu_mul_quant.py --correctness    # correctness only
#   python test_silu_mul_quant.py --perf           # perf only

import argparse

import pandas as pd
import torch

import aiter
from aiter import dtypes
from aiter.test_common import benchmark, checkAllclose, run_perftest

FP8_MAX = {0: 448.0, 1: 57344.0}  # e4m3 / e5m2


def torch_silu_and_mul(input: torch.Tensor) -> torch.Tensor:
    d = input.shape[-1] // 2
    x, y = input.float().split([d, d], dim=-1)
    return torch.nn.functional.silu(x) * y


def ref_int8_quant(act: torch.Tensor):
    scale = act.abs().amax(dim=-1, keepdim=True) / 127.0
    scale = scale.clamp_min(torch.finfo(torch.float32).eps)
    q = torch.round(act / scale).clamp(-127, 127)
    return q.to(torch.int8), scale


def ref_fp8_quant(act: torch.Tensor, fp8type: int):
    m = FP8_MAX[fp8type]
    scale = (act.abs().amax(dim=-1, keepdim=True) / m).clamp_min(1.0 / (m * 512.0))
    q = (act / scale).to(torch.float8_e4m3fn if fp8type == 0 else torch.float8_e5m2)
    return q, scale


def dequant(q, scale):
    return q.float() * scale.float()


def check_dequant(name, act, q, scale, tol):
    # compare on dequantized values normalized by row amax (quant-noise aware)
    if act.numel() == 0:
        return 0.0
    row_amax = act.abs().amax(dim=-1, keepdim=True).clamp_min(1e-6)
    err = (dequant(q, scale) - act).abs() / row_amax
    max_err = err.max().item()
    assert max_err < tol, f"{name}: max normalized dequant err {max_err:.4e} >= {tol}"
    return max_err


# ---------------------------------------------------------------------------
# correctness
# ---------------------------------------------------------------------------


def t_quant_2d(m, n, dtype):
    input = torch.randn(m, n, dtype=dtype, device="cuda")
    act = torch_silu_and_mul(input)
    d = n // 2

    # int8 plain
    q, s = aiter.fuse_silu_mul_quant(input)
    assert q.shape == (m, d) and q.dtype == dtypes.i8 and s.shape == (m, 1)
    e1 = check_dequant(f"int8 m={m} n={n}", act, q, s, tol=0.05)

    # fp8 both types
    for fp8type in (0, 1):
        q8, s8 = aiter.fuse_silu_mul_fp8_quant(input, fp8type)
        expect_dt = torch.float8_e4m3fn if fp8type == 0 else torch.float8_e5m2
        assert q8.dtype == expect_dt
        e2 = check_dequant(f"fp8{fp8type} m={m} n={n}", act, q8, s8, tol=0.2)
    return max(e1, e2)


def t_quant_num_local_tokens(m, n, dtype, topk, local, expect_m):
    # num_tokens*topk rows allocated; only local*topk rows are written
    input = torch.randn(m, n, dtype=dtype, device="cuda")
    act = torch_silu_and_mul(input)
    d = n // 2
    nlt = torch.tensor([local], dtype=torch.int32, device="cuda")

    out = torch.full((m, d), 77, dtype=torch.int8, device="cuda")
    scales = torch.full((m, 1), 77.0, dtype=torch.float32, device="cuda")
    aiter.fuse_silu_mul_quant(input, nlt, topk, expect_m, out, scales)

    valid = min(m, local * topk)
    check_dequant(
        f"nlt m={m} local={local} topk={topk} expect_m={expect_m}",
        act[:valid],
        out[:valid],
        scales[:valid],
        tol=0.05,
    )
    # rows beyond the valid window must stay untouched
    if valid < m:
        assert (out[valid:] == 77).all() and (scales[valid:] == 77).all(), (
            f"rows >= {valid} were written (local={local}, topk={topk})"
        )


def t_quant_expert_ids(m, n, dtype):
    input = torch.randn(m, n, dtype=dtype, device="cuda")
    act = torch_silu_and_mul(input)
    d = n // 2
    expert_ids = torch.zeros(m, dtype=torch.int32, device="cuda")
    drop = torch.rand(m, device="cuda") < 0.3
    expert_ids[drop] = -1
    if not drop.any():  # force at least one masked row
        expert_ids[m // 2] = -1
        drop[m // 2] = True

    out = torch.full((m, d), 77, dtype=torch.int8, device="cuda")
    scales = torch.full((m, 1), 77.0, dtype=torch.float32, device="cuda")
    aiter.fuse_silu_mul_quant(input, expert_ids=expert_ids, output=out, scales=scales)

    keep = ~drop
    check_dequant(f"expert_ids m={m}", act[keep], out[keep], scales[keep], tol=0.05)
    assert (out[drop] == 77).all(), "masked rows were written"


def t_quant_ep(E, T, H, dtype, tokens_per_expert, fp8type=None):
    input = torch.randn(E, T, H, dtype=dtype, device="cuda")
    act = torch_silu_and_mul(input)
    d = H // 2
    if tokens_per_expert is None:
        tpe = None
        counts = [T] * E
    else:
        tpe = torch.tensor(tokens_per_expert, dtype=torch.int32, device="cuda")
        counts = tokens_per_expert
        assert len(tokens_per_expert) == E and max(tokens_per_expert) <= T

    if fp8type is None:
        q, s = aiter.fuse_silu_mul_quant_ep(input, tpe)
        expect_dt = dtypes.i8
    else:
        q, s = aiter.fuse_silu_mul_fp8_quant_ep(input, fp8type, tpe)
        expect_dt = torch.float8_e4m3fn if fp8type == 0 else torch.float8_e5m2
    assert q.shape == (E, T, d) and s.shape == (E, T, 1) and q.dtype == expect_dt

    flat_q = q.view(-1, d)
    flat_s = s.view(-1, 1)
    flat_act = act.view(-1, d)
    valid = torch.zeros(E * T, dtype=torch.bool, device="cuda")
    for e in range(E):
        valid[e * T : e * T + counts[e]] = True
    check_dequant(
        f"ep fp8={fp8type} E={E} T={T} tpe={tokens_per_expert}",
        flat_act[valid],
        flat_q[valid],
        flat_s[valid],
        tol=0.05 if fp8type is None else 0.2,
    )


def t_silu_and_mul_ep(E, T, H, dtype, mask_counts):
    input = torch.randn(E, T, H, dtype=dtype, device="cuda")
    act = torch_silu_and_mul(input)
    out = torch.full((E, T, H // 2), 77.0, dtype=dtype, device="cuda")
    mask_m = torch.tensor(mask_counts, dtype=torch.int32, device="cuda")
    aiter.fuse_silu_and_mul_ep(input, out, mask_m)

    for e in range(E):
        cnt = mask_counts[e]
        if cnt == 0:
            assert (out[e] == 77).all(), f"expert {e} masked rows were written"
            continue
        err = (out[e, :cnt].float() - act[e, :cnt]).abs().max().item()
        denom = act[e, :cnt].abs().max().item() + 1e-6
        assert err / denom < 1e-2, f"ep silu expert {e}: rel err {err/denom:.3e}"
        if cnt < T:
            assert (out[e, cnt:] == 77).all(), f"expert {e} rows >= {cnt} were written"


def t_relu2(m, n, dtype):
    input = torch.randn(m, n, dtype=dtype, device="cuda") * 3
    out = aiter.relu2(input)
    ref = torch.relu(input.float()).square().to(dtype)
    checkAllclose(ref.float(), out.float(), rtol=2e-2, atol=2e-2, msg=f"relu2 {dtype}")


def t_generic_entry(m, n, dtype):
    input = torch.randn(m, n, dtype=dtype, device="cuda")
    act = torch_silu_and_mul(input)
    for dt, tol in [
        (torch.int8, 0.05),
        (torch.float8_e4m3fn, 0.2),
        (torch.float8_e5m2, 0.2),
    ]:
        q, s = aiter.fuse_silu_mul_per_token_quant(input, dtype=dt)
        check_dequant(f"generic {dt}", act, q, s, tol=tol)


def t_zero_tokens():
    input = torch.randn(0, 128, dtype=torch.bfloat16, device="cuda")
    q, s = aiter.fuse_silu_mul_quant(input)
    assert q.shape[0] == 0
    x3 = torch.randn(2, 0, 128, dtype=torch.bfloat16, device="cuda")
    q3, s3 = aiter.fuse_silu_mul_quant_ep(x3)
    assert q3.shape[1] == 0


def t_host_checks():
    """R2 shape checks raise; unaligned bases (R3) fall back and stay correct."""
    x = torch.randn(8, 64, dtype=torch.bfloat16, device="cuda")
    out = torch.empty(8, 32, dtype=torch.int8, device="cuda")
    bad_odd = torch.randn(8, 65, dtype=torch.bfloat16, device="cuda")
    bad_scales = torch.empty(8, 2, dtype=torch.float32, device="cuda")[:, :1]
    short_eids = torch.zeros(4, dtype=torch.int32, device="cuda")
    cases = [
        (lambda: aiter.fuse_silu_mul_quant(bad_odd), "even"),
        (lambda: aiter.fuse_silu_mul_quant(x, output=out[:4]), "out must have"),
        (lambda: aiter.fuse_silu_mul_quant(x, scales=bad_scales), "scales must be contiguous"),
        (lambda: aiter.fuse_silu_mul_quant(x, expert_ids=short_eids), "expert_ids must cover"),
    ]
    for fn, msg in cases:
        try:
            fn()
        except RuntimeError as e:
            assert msg in str(e), f"unexpected error: {e}"
        else:
            raise AssertionError(f"expected TORCH_CHECK failure containing '{msg}'")

    # base address misaligned to the element size: must take the generic
    # kernel and remain numerically correct
    for m, n in ((33, 128), (513, 8192)):
        base = torch.randn(m * n + 1, dtype=torch.bfloat16, device="cuda")
        uin = base[1 : 1 + m * n].view(m, n)
        act = torch_silu_and_mul(uin)
        q, s = aiter.fuse_silu_mul_quant(uin)
        check_dequant(f"unaligned int8 m={m}", act, q, s, tol=0.05)
        q8, s8 = aiter.fuse_silu_mul_fp8_quant(uin)
        check_dequant(f"unaligned fp8 m={m}", act, q8, s8, tol=0.2)

    # unaligned EP input
    E, T, H = 2, 8, 1024
    base = torch.randn(E * T * H + 1, dtype=torch.bfloat16, device="cuda")
    uin3 = base[1 : 1 + E * T * H].view(E, T, H)
    act3 = torch_silu_and_mul(uin3)
    tpe = torch.tensor([8, 5], dtype=torch.int32, device="cuda")
    q3, s3 = aiter.fuse_silu_mul_quant_ep(uin3, tpe)
    valid = torch.zeros(E * T, dtype=torch.bool, device="cuda")
    valid[: tpe[0]] = True  # expert 0: tokens [0, 8)
    valid[T : T + tpe[1]] = True  # expert 1: tokens [8, 13)
    check_dequant(
        "unaligned ep",
        act3.view(-1, H // 2)[valid],
        q3.view(-1, H // 2)[valid],
        s3.view(-1, 1)[valid],
        tol=0.05,
    )

def run_correctness():
    for dtype in (torch.bfloat16, torch.float16):
        # plain 2D over dispatch-table d buckets incl. 
        for d in (48, 80, 96, 160, 192, 384, 512, 1024, 1026, 2048, 4096, 7168):
            t_quant_2d(33, 2 * d, dtype)
        # m >= 512 selects the VEC16 dispatch buckets (d = 2048/4096/7168)
        for d in (2048, 4096, 7168):
            t_quant_2d(513, 2 * d, dtype)
        # d % 16 != 0 with m >= 512: VEC8 fallback inside the wide regime
        t_quant_2d(520, 2064, dtype)
        # num_local_tokens x topk x expect_m
        for topk in (1, 8):
            for local in (0, 8, 17, 64):
                for expect_m in (-1, 1, 8, 64):
                    t_quant_num_local_tokens(128, 8192, dtype, topk, local, expect_m)
        # grid-stride path (num_tokens >= 8192)
        t_quant_num_local_tokens(8192, 2048, dtype, 8, 512, -1)
        t_quant_num_local_tokens(16384, 1024, dtype, 8, 1024, -1)
        # expert_ids
        t_quant_expert_ids(256, 4096, dtype)
        # EP int8/fp8
        for tpe in (
            [1, 3, 1, 9, 20, 1, 1, 0, 1, 1, 1, 11, 0, 2, 4, 1],
            [16, 15, 14, 16, 12, 18, 15, 15, 16, 14, 15, 17, 12, 18, 10, 10],
            [30] * 16,
            [0] * 16,
        ):
            t_quant_ep(16, 32, 1024, dtype, tpe)
            t_quant_ep(16, 32, 1024, dtype, tpe, fp8type=0)
            t_quant_ep(16, 32, 1024, dtype, tpe, fp8type=1)
        # no-mask EP (nullptr)
        t_quant_ep(4, 8, 512, dtype, None)
        # EP with d = 4096: exercises the VEC16 buckets (E*T >= 512)
        tpe_wide = [128, 4, 64, 32, 128, 1, 3, 0, 9, 128, 7, 128, 2, 128, 128, 128]
        t_quant_ep(16, 128, 8192, dtype, tpe_wide)
        t_quant_ep(16, 128, 8192, dtype, tpe_wide, fp8type=0)
        # quantized EP generic path (d = 513, no vector bucket matches)
        t_quant_ep(2, 8, 1026, dtype, [8, 6])
        # non-quant EP activation
        t_silu_and_mul_ep(8, 32, 512, dtype, [10, 32, 0, 1, 5, 32, 7, 0])
        t_silu_and_mul_ep(4, 16, 1026, dtype, [16, 8, 0, 16])  # odd-d generic path
        # generic entry
        t_generic_entry(64, 2048, dtype)
        # relu2
        t_relu2(128, 512, dtype)
        t_relu2(64, 168, dtype)  # multirow special dims
        t_relu2(64, 336, dtype)
        t_relu2(64, 672, dtype)
        t_relu2(128, 1000, dtype)  # non %8 fallback
    t_relu2(64, 512, torch.float32)
    t_zero_tokens()
    t_host_checks()
    print("[Correctness] All tests passed")


# ---------------------------------------------------------------------------
# perf
# ---------------------------------------------------------------------------


@benchmark()
def test_fuse_silu_mul_quant_perf(m, n, dtype):
    ret = {}
    input = torch.randn(m, n, dtype=dtype, device="cuda")
    d = n // 2

    out = torch.empty(m, d, dtype=dtypes.i8, device="cuda")
    scales = torch.empty(m, 1, dtype=torch.float32, device="cuda")
    _, us_fused = run_perftest(
        aiter.fuse_silu_mul_quant, input, output=out, scales=scales
    )

    # unfused baseline: silu_and_mul + per-token quant (2 kernels, 1 extra roundtrip)
    act = torch.empty(m, d, dtype=dtype, device="cuda")

    def unfused(input=input, act=act):
        aiter.silu_and_mul(act, input)
        return aiter.per_token_quant_hip(act)

    _, us_unfused = run_perftest(unfused)

    act_ref = torch_silu_and_mul(input)
    q, s = aiter.fuse_silu_mul_quant(input)
    err = check_dequant("perf-int8", act_ref, q, s, tol=0.05)
    ret["us_fused"] = us_fused
    ret["us_unfused(silu+quant)"] = us_unfused
    ret["speedup"] = us_unfused / us_fused
    ret["TB/s_fused"] = (input.nbytes + out.nbytes) / us_fused / 1e6
    ret["err"] = err
    return ret


@benchmark()
def test_fuse_silu_mul_fp8_quant_perf(m, n, dtype):
    ret = {}
    input = torch.randn(m, n, dtype=dtype, device="cuda")
    _, us = run_perftest(aiter.fuse_silu_mul_fp8_quant, input)
    ret["us"] = us
    ret["TB/s"] = (input.nbytes + input.nbytes / 2) / us / 1e6
    return ret


@benchmark()
def test_fuse_silu_mul_quant_ep_perf(E, T, H, dtype):
    ret = {}
    input = torch.randn(E, T, H, dtype=dtype, device="cuda")
    tpe = torch.full((E,), T, dtype=torch.int32, device="cuda")
    _, us = run_perftest(aiter.fuse_silu_mul_quant_ep, input, tpe)
    ret["us"] = us
    ret["TB/s"] = (input.nbytes + input.nbytes / 2) / us / 1e6
    return ret


def _print_rows(title, rows):
    # one table per benchmark family: their dicts have disjoint keys, and
    # merging them turns every inapplicable cell into a confusing NaN
    print(f"\n[{title}]")
    print(pd.DataFrame(rows).to_string(na_rep="-"))


def run_perf():
    rows = []
    for m in (1, 64, 512, 4096, 8192):
        rows.append(test_fuse_silu_mul_quant_perf(m, 8192, torch.bfloat16))
    _print_rows("perf 2D int8 fused vs unfused", rows)
    _print_rows(
        "perf 2D fp8 e4m3", [test_fuse_silu_mul_fp8_quant_perf(4096, 8192, torch.bfloat16)]
    )
    _print_rows("perf ep int8", [test_fuse_silu_mul_quant_ep_perf(16, 256, 8192, torch.bfloat16)])


if __name__ == "__main__":
    parser = argparse.ArgumentParser()
    parser.add_argument("--correctness", action="store_true")
    parser.add_argument("--perf", action="store_true")
    args = parser.parse_args()
    if not args.perf:
        run_correctness()
    if not args.correctness:
        run_perf()
