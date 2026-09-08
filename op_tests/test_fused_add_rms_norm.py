# SPDX-License-Identifier: MIT

import torch
import torch.nn.functional as F
import aiter
from aiter.test_common import perftest
from aiter import dtypes
import argparse

PERF_ROWS = []


def _fmt_us(val):
    return f"{val:.2f}"


@perftest()
def run_torch_fused_add_rms(input, residual, weight, eps):
    residual_out = input + residual
    output = F.rms_norm(
        input=residual_out,
        normalized_shape=(input.shape[-1],),
        weight=weight,
        eps=eps,
    )
    return output, residual_out


@perftest()
def run_ck_fused_add_rms(input, residual, weight, eps):
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
def run_cu_fused_add_rms(input, residual, weight, eps):
    # In-place: input and residual are modified
    aiter.fused_add_rms_norm_cu(input, residual, weight, eps)
    output = input
    residual_out = residual
    return output, residual_out


def test_fused_add_rms_norm_cu(dtype, m, n):
    dim = (m, n)
    # Use fresh clones so each implementation gets the same input
    input_ref = torch.randn(dim, dtype=dtype, device="cuda")
    residual_ref = torch.randn(dim, dtype=dtype, device="cuda")
    weight = torch.randn(n, dtype=dtype, device="cuda")
    eps = 1e-5

    # torch baseline
    (a, res_a, *_), t_torch = run_torch_fused_add_rms(
        input_ref.clone(), residual_ref.clone(), weight, eps
    )

    # ck
    (b, res_b, *_), t_ck = run_ck_fused_add_rms(
        input_ref.clone(), residual_ref.clone(), weight, eps
    )

    # cu
    (c, res_c, *_), t_cu = run_cu_fused_add_rms(
        input_ref.clone(), residual_ref.clone(), weight, eps
    )

    uplift_ck = t_torch / t_ck if t_ck > 0 else float("inf")
    uplift_cu = t_torch / t_cu if t_cu > 0 else float("inf")

    print(
        f"[perf] m={m:<4d} n={n:<4d} dtype={str(dtype):<6s}  "
        f"torch: {_fmt_us(t_torch):>8s} us  "
        f"ck: {_fmt_us(t_ck):>8s} us (x{uplift_ck:.1f})  "
        f"cu: {_fmt_us(t_cu):>8s} us (x{uplift_cu:.1f})"
    )

    PERF_ROWS.append(
        {
            "m": m,
            "n": n,
            "dtype": str(dtype),
            "torch_us": t_torch,
            "ck_us": t_ck,
            "cu_us": t_cu,
            "uplift_ck": uplift_ck,
            "uplift_cu": uplift_cu,
        }
    )

    # Correctness checks
    cos_out = F.cosine_similarity(a.flatten(), c.flatten(), dim=0).item()
    cos_res = F.cosine_similarity(res_a.flatten(), res_c.flatten(), dim=0).item()
    print(
        f"[cos]   m={m:<4d} n={n:<4d} dtype={str(dtype):<6s}  "
        f"out(torch,cu): {cos_out:.6f}  res(torch,cu): {cos_res:.6f}"
    )

    return True


def print_perf_summary(rows):
    if not rows:
        print("\nNo results to summarize.")
        return

    title = "[Perf Summary] fused_add_rms_norm_cu"
    print("\n" + "=" * len(title))
    print(title)
    print("=" * len(title))

    header_cols = [
        ("m", "m"),
        ("n", "n"),
        ("dtype", "dtype"),
        ("torch(us)", "torch_us"),
        ("ck(us)", "ck_us"),
        ("cu(us)", "cu_us"),
        ("uplift_ck", "uplift_ck"),
        ("uplift_cu", "uplift_cu"),
    ]

    formatted = []
    for r in rows:
        formatted.append(
            {
                "m": f"{r['m']}",
                "n": f"{r['n']}",
                "dtype": r["dtype"],
                "torch_us": _fmt_us(r["torch_us"]),
                "ck_us": _fmt_us(r["ck_us"]),
                "cu_us": _fmt_us(r["cu_us"]),
                "uplift_ck": f"{r['uplift_ck']:.2f}x",
                "uplift_cu": f"{r['uplift_cu']:.2f}x",
            }
        )

    widths = {
        k: max(len(k), *(len(fr[h]) for fr in formatted))
        for k, h in header_cols
    }

    header_line = " | ".join(f"{k:<{widths[k]}}" for k, h in header_cols)
    sep = "-+-".join("-" * widths[k] for k, _ in header_cols)
    print(header_line)
    print(sep)
    for fr in formatted:
        print(" | ".join(f"{fr[h]:<{widths[k]}}" for k, h in header_cols))


# Default test grid
l_dtype = ["fp16"]
l_m = [1, 128, 1024]
l_n = [1024, 4096]

parser = argparse.ArgumentParser(
    formatter_class=argparse.RawTextHelpFormatter,
    description="Performance test for fused_add_rms_norm_cu",
)
parser.add_argument(
    "-d", "--dtype", type=str, choices=["fp16", "bf16"], default=None,
    help="Data type, e.g. -d bf16"
)
parser.add_argument(
    "-m", "--m", type=int, default=None,
    help="M dimension"
)
parser.add_argument(
    "-n", "--n", type=int, default=None,
    help="N dimension"
)

args = parser.parse_args()

if args.dtype is not None:
    l_dtype = [args.dtype]
else:
    l_dtype = ["fp16"]

if args.m is not None:
    l_m = [args.m]
if args.n is not None:
    l_n = [args.n]

print("\n=== fused_add_rms_norm_cu perf test ===")
print(f"  dtypes: {l_dtype}")
print(f"  m: {l_m}")
print(f"  n: {l_n}")
print()

for dtype_str in l_dtype:
    dt = getattr(dtypes, dtype_str)
    for m in l_m:
        for n in l_n:
            test_fused_add_rms_norm_cu(dt, m, n)

print_perf_summary(PERF_ROWS)
