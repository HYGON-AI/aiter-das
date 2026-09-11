# SPDX-License-Identifier: MIT
# Copyright (C) 2024-2025, Advanced Micro Devices, Inc. All rights reserved.
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.

import torch
import torch.nn.functional as F
import aiter
from aiter.test_common import checkAllclose, perftest
from aiter import dtypes
import argparse
import pandas as pd


def rmsnorm_bytes(m, n, dtype, fuse_add=False):
    """Effective HBM traffic estimate for RMSNorm.

    plain:  read x(M,N) + weight(N), write y(M,N)
    fuseAdd: read x+res + weight, write out+res_out
    """
    es = torch.tensor([], dtype=dtype).element_size()
    weight_bytes = n * es
    if fuse_add:
        # read x, residual; write out, residual_out
        return (4 * m * n) * es + weight_bytes
    return (2 * m * n) * es + weight_bytes


def eff_bw_gbs(num_bytes, avg_us):
    """Effective bandwidth in GB/s from bytes and latency in us."""
    if avg_us is None or avg_us <= 0:
        return None
    return num_bytes / avg_us * 1e-3  # bytes / us * 1e-3 = GB/s


def fmt_bw(bw):
    return round(bw, 2) if bw is not None else "N/A"


@perftest()
def run_torch(input, weight, eps, residual=None):
    if residual is None:
        residual_out = None
        output = F.rms_norm(
            input=input, normalized_shape=(input.shape[-1],), weight=weight, eps=eps
        )
    else:
        residual_out = input + residual
        output = F.rms_norm(
            input=residual_out,
            normalized_shape=(input.shape[-1],),
            weight=weight,
            eps=eps,
        )
    return output, residual_out


@perftest()
def run_ck(input, weight, eps, residual=None):
    if residual is None:
        residual_out = None
        output = aiter.rms_norm(input, weight, eps)
    else:
        residual_out = torch.empty_like(input)
        output = torch.empty_like(input)
        aiter.rmsnorm2d_fwd_with_add(
            output,
            input,
            residual,
            residual_out,
            weight,
            eps,
        )
    return output, residual_out


@perftest()
def run_cu(input, weight, eps, residual=None):
    if residual is None:
        residual_out = None
        output = torch.empty_like(input)
        aiter.rms_norm_cu(output, input, weight, eps)
    else:
        # in-place kernel; safe under @perftest only when args are rotated clones.
        # Do not use returned tensors for accuracy — see test_rmsnorm2d_fuseAdd.
        aiter.fused_add_rms_norm_cu(input, residual, weight, eps)
        output = input
        residual_out = residual
    return output, residual_out


def run_cu_fuse_add_once(input, residual, weight, eps):
    """One-shot correctness path for in-place fused_add_rms_norm_cu."""
    x = input.clone()
    r = residual.clone()
    aiter.fused_add_rms_norm_cu(x, r, weight, eps)
    return x, r


def test_rmsnorm2d(dtype, m, n):
    dim = (m, n)
    input = torch.randn(dim, dtype=dtype, device="cuda")
    weight = torch.randn(n, dtype=dtype, device="cuda")
    (a, *_), avg_a = run_torch(input, weight, 1e-5)
    (b, *_), avg_b = run_ck(input, weight, 1e-5)
    (c, *_), avg_c = run_cu(input, weight, 1e-5)

    nbytes = rmsnorm_bytes(m, n, dtype, fuse_add=False)
    torch_bw = eff_bw_gbs(nbytes, avg_a)
    ck_bw = eff_bw_gbs(nbytes, avg_b)
    cu_bw = eff_bw_gbs(nbytes, avg_c)

    msg = (
        f"[perf] dim: {str(dim):<20}, dtype: {dtype}, "
        f"torch avg: {avg_a:<8.2f} us ({fmt_bw(torch_bw)} GB/s), "
        f"ck avg: {avg_b:<8.2f} us ({fmt_bw(ck_bw)} GB/s), "
        f"cu avg: {avg_c:<8.2f} us ({fmt_bw(cu_bw)} GB/s), "
        f"uplift(ck/torch): {avg_a/avg_b-1:<5.1%}"
    )
    assert torch.isfinite(b).all(), (
        "Non-finite output in test_rmsnorm2d (ck output): "
        f"{m=}, {n=}, {dim=}, {dtype=}, backend=ck"
    )
    assert torch.isfinite(c).all(), (
        "Non-finite output in test_rmsnorm2d (cu output): "
        f"{m=}, {n=}, {dim=}, {dtype=}, backend=cu"
    )
    ck_ret = checkAllclose(a, b, msg=msg)
    assert ck_ret <= 0.03, (
        "Accuracy check failed in test_rmsnorm2d (ck output): "
        f"{m=}, {n=}, {dim=}, {dtype=}, "
        f"error_ratio={ck_ret:.6f}, tolerance=0.03"
    )
    cu_ret = checkAllclose(a, c, msg="cu")
    assert cu_ret <= 0.03, (
        "Accuracy check failed in test_rmsnorm2d (cu output): "
        f"{m=}, {n=}, {dim=}, {dtype=}, "
        f"error_ratio={cu_ret:.6f}, tolerance=0.03"
    )
    ck_acc = "passed" if ck_ret == 0 else (1 - ck_ret)
    cu_acc = "passed" if cu_ret == 0 else (1 - cu_ret)

    return {
        "m": m,
        "n": n,
        "dtype": str(dtype),
        "bytes": nbytes,
        "torch_us": round(avg_a, 2),
        "ck_us": round(avg_b, 2),
        "cu_us": round(avg_c, 2),
        "torch_bw_GBs": fmt_bw(torch_bw),
        "ck_bw_GBs": fmt_bw(ck_bw),
        "cu_bw_GBs": fmt_bw(cu_bw),
        "cu_vs_ck": f"{avg_b / avg_c:.2f}x" if avg_c > 0 else "N/A",
        "ck_vs_torch": f"{avg_a / avg_b:.2f}x" if avg_b > 0 else "N/A",
        "cu_vs_torch": f"{avg_a / avg_c:.2f}x" if avg_c > 0 else "N/A",
        "ck_acc": ck_acc,
        "cu_acc": cu_acc,
    }


def test_rmsnorm2d_fuseAdd(dtype, m, n):
    dim = (m, n)
    input = torch.randn(dim, dtype=dtype, device="cuda")
    weight = torch.randn(n, dtype=dtype, device="cuda")
    res = torch.randn(dim, dtype=dtype, device="cuda")
    (a, res_a, *_), avg_a = run_torch(input, weight, 1e-5, residual=res)
    (b, res_b, *_), avg_b = run_ck(input, weight, 1e-5, residual=res)
    # timing only: @perftest re-runs in-place and corrupts returned tensors
    _, avg_c = run_cu(input.clone(), weight, 1e-5, residual=res.clone())
    c, res_c = run_cu_fuse_add_once(input, res, weight, 1e-5)

    nbytes = rmsnorm_bytes(m, n, dtype, fuse_add=True)
    torch_bw = eff_bw_gbs(nbytes, avg_a)
    ck_bw = eff_bw_gbs(nbytes, avg_b)
    cu_bw = eff_bw_gbs(nbytes, avg_c)

    # bf16 has coarser mantissa; CK tile reduce vs torch can leave ~1-2 ULP outliers
    atol = 0.08 if dtype == dtypes.bf16 else 0.03
    msg = (
        f"[perf] dim: {str(dim):<20}, dtype: {dtype}, "
        f"torch avg: {avg_a:<8.2f} us ({fmt_bw(torch_bw)} GB/s), "
        f"ck avg: {avg_b:<8.2f} us ({fmt_bw(ck_bw)} GB/s), "
        f"cu avg: {avg_c:<8.2f} us ({fmt_bw(cu_bw)} GB/s)"
    )
    assert torch.isfinite(b).all(), (
        "Non-finite output in test_rmsnorm2d_fuseAdd (ck output): "
        f"{m=}, {n=}, {dim=}, {dtype=}, backend=ck"
    )
    assert torch.isfinite(res_b).all(), (
        "Non-finite output in test_rmsnorm2d_fuseAdd (ck residual): "
        f"{m=}, {n=}, {dim=}, {dtype=}, backend=ck"
    )
    assert torch.isfinite(c).all(), (
        "Non-finite output in test_rmsnorm2d_fuseAdd (cu output): "
        f"{m=}, {n=}, {dim=}, {dtype=}, backend=cu"
    )
    assert torch.isfinite(res_c).all(), (
        "Non-finite output in test_rmsnorm2d_fuseAdd (cu residual): "
        f"{m=}, {n=}, {dim=}, {dtype=}, backend=cu"
    )
    ck_ret = checkAllclose(a, b, atol=atol, rtol=0.001, msg=msg)
    assert ck_ret <= 0.03, (
        "Accuracy check failed in test_rmsnorm2d_fuseAdd (ck output): "
        f"{m=}, {n=}, {dim=}, {dtype=}, {atol=}, rtol=0.001, "
        f"error_ratio={ck_ret:.6f}, tolerance=0.03"
    )
    ck_residual_ret = checkAllclose(
        res_a, res_b, atol=atol, rtol=0.001, msg="ck res check"
    )
    assert ck_residual_ret <= 0.03, (
        "Accuracy check failed in test_rmsnorm2d_fuseAdd (ck residual): "
        f"{m=}, {n=}, {dim=}, {dtype=}, {atol=}, rtol=0.001, "
        f"error_ratio={ck_residual_ret:.6f}, tolerance=0.03"
    )
    cu_ret = checkAllclose(a, c, atol=atol, rtol=0.001, msg="cu")
    assert cu_ret <= 0.03, (
        "Accuracy check failed in test_rmsnorm2d_fuseAdd (cu output): "
        f"{m=}, {n=}, {dim=}, {dtype=}, {atol=}, rtol=0.001, "
        f"error_ratio={cu_ret:.6f}, tolerance=0.03"
    )
    cu_residual_ret = checkAllclose(
        res_a, res_c, atol=atol, rtol=0.001, msg="cu res check"
    )
    assert cu_residual_ret <= 0.03, (
        "Accuracy check failed in test_rmsnorm2d_fuseAdd (cu residual): "
        f"{m=}, {n=}, {dim=}, {dtype=}, {atol=}, rtol=0.001, "
        f"error_ratio={cu_residual_ret:.6f}, tolerance=0.03"
    )
    ck_acc = "passed" if ck_ret == 0 else (1 - ck_ret)
    cu_acc = "passed" if cu_ret == 0 else (1 - cu_ret)

    return {
        "m": m,
        "n": n,
        "dtype": str(dtype),
        "bytes": nbytes,
        "torch_us": round(avg_a, 2),
        "ck_us": round(avg_b, 2),
        "cu_us": round(avg_c, 2),
        "torch_bw_GBs": fmt_bw(torch_bw),
        "ck_bw_GBs": fmt_bw(ck_bw),
        "cu_bw_GBs": fmt_bw(cu_bw),
        "cu_vs_ck": f"{avg_b / avg_c:.2f}x" if avg_c > 0 else "N/A",
        "ck_vs_torch": f"{avg_a / avg_b:.2f}x" if avg_b > 0 else "N/A",
        "cu_vs_torch": f"{avg_a / avg_c:.2f}x" if avg_c > 0 else "N/A",
        "ck_acc": ck_acc,
        "cu_acc": cu_acc,
    }


# for dtype in [dtypes.fp16, dtypes.bf16]:
#     for m in [1, 2, 4, 8, 16, 32, 64, 128, 256]:
#         for n in [4096, 8192, 16384, 32768, 65536]:
#             test_rmsnorm2d(dtype, m, n)

# l_dtype = ["fp16", "bf16"]
# l_m = [1, 2, 4, 8, 16, 32, 64, 128, 256]
# l_n = [4096, 8192, 16384, 32768, 65536]

l_dtype = ["fp16", "bf16"]
l_m = [1*56, 10*56, 32*56, 64*56, 128*56]
l_n = [1232, 4096]

parser = argparse.ArgumentParser(
    formatter_class=argparse.RawTextHelpFormatter,
    description="config input of test",
)
parser.add_argument(
    "-d",
    "--dtype",
    type=str,
    choices=["fp16", "bf16"],
    nargs="?",
    const=None,
    default=None,
    help="""Data type.
    e.g.: -d bf16""",
)
parser.add_argument(
    "-m",
    "--m",
    type=int,
    nargs="?",
    default=None,
    help="""M of mnk.
    e.g.: -m 32""",
)
parser.add_argument(
    "-n",
    "--n",
    type=int,
    nargs="?",
    default=None,
    help="""N of mnk.
    e.g.: -n 1024""",
)
parser.add_argument(
    "--fuse-add",
    action=argparse.BooleanOptionalAction,
    default=True,
    help="Also run rmsnorm2d fuseAdd path (default: True). Use --no-fuse-add to skip.",
)

args = parser.parse_args()
if args.dtype is None:
    l_dtype = [dtypes.d_dtypes[key] for key in l_dtype]
else:
    l_dtype = [dtypes.d_dtypes[args.dtype]]
if args.m is not None:
    l_m = [args.m]
if args.n is not None:
    l_n = [args.n]

print("\nstart rmsnorm2d test (torch / ck / cu)")
failed_cases = []


def run_accuracy_case(test_func, *args, **kwargs):
    try:
        return test_func(*args, **kwargs)
    except AssertionError as exc:
        failed_cases.append(str(exc))
        print(f"[ACCURACY FAILED] {exc}", flush=True)
        return None
df_rows = []
for dtype in l_dtype:
    for m in l_m:
        for n in l_n:
            ret = run_accuracy_case(test_rmsnorm2d, dtype, m, n)
            if ret is not None:
                df_rows.append(ret)

SHOW_COLS = [
    "m",
    "n",
    "dtype",
    "torch_us",
    "ck_us",
    "cu_us",
    "torch_bw_GBs",
    "ck_bw_GBs",
    "cu_bw_GBs",
    "cu_vs_ck",
    "ck_vs_torch",
    "cu_vs_torch",
    "ck_acc",
    "cu_acc",
]

if df_rows:
    df = pd.DataFrame(df_rows)
    print("\n========== rmsnorm2d CU vs CK performance ==========")
    print(df[SHOW_COLS].to_string(index=False))
    df[SHOW_COLS].to_csv("rmsnorm2d.csv", index=False)
    print("\nsaved: rmsnorm2d.csv")

if args.fuse_add:
    print("\nstart fuse add test")
    df_fuse_rows = []
    for dtype in l_dtype:
        for m in l_m:
            for n in l_n:
                ret = run_accuracy_case(
                    test_rmsnorm2d_fuseAdd, dtype, m, n
                )
                if ret is not None:
                    df_fuse_rows.append(ret)
    if df_fuse_rows:
        df_fuse = pd.DataFrame(df_fuse_rows)
        print("\n========== rmsnorm2d fuseAdd CU vs CK performance ==========")
        print(df_fuse[SHOW_COLS].to_string(index=False))
        df_fuse[SHOW_COLS].to_csv("rmsnorm2d_fuseAdd.csv", index=False)
        print("\nsaved: rmsnorm2d_fuseAdd.csv")

if failed_cases:
    details = "\n".join(
        f"[{index}] {message}"
        for index, message in enumerate(failed_cases, start=1)
    )
    raise AssertionError(
        f"{len(failed_cases)} accuracy case(s) failed:\n{details}"
    )
