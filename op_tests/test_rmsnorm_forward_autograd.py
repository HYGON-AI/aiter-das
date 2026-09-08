# SPDX-License-Identifier: MIT

import argparse
import time

import torch
import torch.nn.functional as F

from aiter import dtypes
from aiter.ops.rmsnorm import (
    rmsnorm_backward_autograd,
    rmsnorm_forward,
    rmsnorm_forward_autograd,
)
from aiter.test_common import checkAllclose

EPS = 1e-5


def torch_rmsnorm_ref(x, weight, eps=EPS):
    return F.rms_norm(
        x,
        normalized_shape=(x.shape[-1],),
        weight=weight,
        eps=eps,
    )


def _measure_cuda_ms(fn, *args, **kwargs):
    _ = fn(*args, **kwargs)
    torch.cuda.synchronize()
    start = torch.cuda.Event(enable_timing=True)
    end = torch.cuda.Event(enable_timing=True)
    start.record()
    out = fn(*args, **kwargs)
    end.record()
    torch.cuda.synchronize()
    return out, start.elapsed_time(end)


def test_rmsnorm_forward(dtype, m, n):
    """Forward-only: rmsnorm_forward_autograd vs torch reference."""
    dim = (m, n)
    x = torch.randn(dim, dtype=dtype, device="cuda")
    weight = torch.randn(n, dtype=dtype, device="cuda")

    ref, t_torch_fwd = _measure_cuda_ms(
        lambda: torch_rmsnorm_ref(x.float(), weight.float(), EPS).to(dtype)
    )

    y_infer, rstd_infer, t_infer = None, None, None
    y_infer, rstd_infer = rmsnorm_forward(x, weight, EPS, training=False)
    torch.cuda.synchronize()
    start = torch.cuda.Event(enable_timing=True)
    end = torch.cuda.Event(enable_timing=True)
    start.record()
    y_infer, rstd_infer = rmsnorm_forward(x, weight, EPS, training=False)
    end.record()
    torch.cuda.synchronize()
    t_infer = start.elapsed_time(end)
    assert rstd_infer.numel() == 0, f"expected empty rstd, got shape {rstd_infer.shape}"
    checkAllclose(
        ref,
        y_infer,
        atol=0.02,
        rtol=0.002,
        msg=f"[forward infer] dim={dim}, dtype={dtype}",
    )
    print(f"  [timing] rmsnorm_forward(infer)  {t_infer:.3f} ms  (torch ref {t_torch_fwd:.3f} ms)")

    start = torch.cuda.Event(enable_timing=True)
    end = torch.cuda.Event(enable_timing=True)
    start.record()
    y_train, rstd_train = rmsnorm_forward(x, weight, EPS, training=True)
    end.record()
    torch.cuda.synchronize()
    t_train = start.elapsed_time(end)
    assert rstd_train.shape == (m,), f"expected rstd shape ({m},), got {rstd_train.shape}"
    assert rstd_train.dtype == torch.float32
    checkAllclose(
        ref,
        y_train,
        atol=0.02,
        rtol=0.002,
        msg=f"[forward train] dim={dim}, dtype={dtype}",
    )
    print(f"  [timing] rmsnorm_forward(train)  {t_train:.3f} ms  (torch ref {t_torch_fwd:.3f} ms)")

    return {
        "torch_fwd": t_torch_fwd,
        "aiter_fwd_infer": t_infer,
        "aiter_fwd_train": t_train,
    }


def test_rmsnorm_forward_autograd(dtype, m, n):
    """Autograd forward/backward vs torch reference."""
    dim = (m, n)
    x = torch.randn(dim, dtype=dtype, device="cuda", requires_grad=True)
    weight = torch.randn(n, dtype=dtype, device="cuda", requires_grad=True)

    x_ref = x.detach().clone().float().requires_grad_(True)
    weight_ref = weight.detach().clone().float().requires_grad_(True)

    _ = rmsnorm_forward_autograd(x, weight, EPS, training=True)
    torch.cuda.synchronize()
    start = torch.cuda.Event(enable_timing=True)
    end = torch.cuda.Event(enable_timing=True)
    start.record()
    out = rmsnorm_forward_autograd(x, weight, EPS, training=True)
    end.record()
    torch.cuda.synchronize()
    t_aiter_fwd = start.elapsed_time(end)

    _ = torch_rmsnorm_ref(x_ref, weight_ref, EPS)
    torch.cuda.synchronize()
    start = torch.cuda.Event(enable_timing=True)
    end = torch.cuda.Event(enable_timing=True)
    start.record()
    ref = torch_rmsnorm_ref(x_ref, weight_ref, EPS)
    end.record()
    torch.cuda.synchronize()
    t_torch_fwd = start.elapsed_time(end)

    cos_sim = F.cosine_similarity(
        out.float().flatten(), ref.detach().flatten(), dim=0
    ).item()
    print(
        f"[autograd-fwd] dim={dim}, dtype={dtype}, cos(ref,aiter)={cos_sim:.8f}"
    )
    checkAllclose(
        ref.to(dtype),
        out,
        atol=0.02,
        rtol=0.002,
        msg=f"[autograd forward] dim={dim}, dtype={dtype}",
    )

    grad_out = torch.randn_like(out)
    torch.cuda.synchronize()
    start = torch.cuda.Event(enable_timing=True)
    end = torch.cuda.Event(enable_timing=True)
    start.record()
    out.backward(grad_out, retain_graph=False)
    end.record()
    torch.cuda.synchronize()
    t_aiter_bwd = start.elapsed_time(end)

    torch.cuda.synchronize()
    start = torch.cuda.Event(enable_timing=True)
    end = torch.cuda.Event(enable_timing=True)
    start.record()
    ref.backward(grad_out.float())
    end.record()
    torch.cuda.synchronize()
    t_torch_bwd = start.elapsed_time(end)

    checkAllclose(
        x_ref.grad,
        x.grad.float(),
        atol=0.05,
        rtol=0.01,
        msg=f"[autograd dx] dim={dim}, dtype={dtype}",
    )
    checkAllclose(
        weight_ref.grad,
        weight.grad.float(),
        atol=0.05,
        rtol=0.01,
        msg=f"[autograd dweight] dim={dim}, dtype={dtype}",
    )
    print(f"  [timing] autograd fwd aiter {t_aiter_fwd:.3f} / torch {t_torch_fwd:.3f} ms  |  bwd aiter {t_aiter_bwd:.3f} / torch {t_torch_bwd:.3f} ms")

    return {
        "torch_fwd": t_torch_fwd,
        "aiter_fwd": t_aiter_fwd,
        "torch_bwd": t_torch_bwd,
        "aiter_bwd": t_aiter_bwd,
    }


def test_rmsnorm_backward_api(dtype, m, n):
    """Explicit rmsnorm_backward_autograd API vs torch autograd."""
    dim = (m, n)
    x = torch.randn(dim, dtype=dtype, device="cuda", requires_grad=True)
    weight = torch.randn(n, dtype=dtype, device="cuda", requires_grad=True)

    x_ref = x.detach().clone().float().requires_grad_(True)
    weight_ref = weight.detach().clone().float().requires_grad_(True)

    _ = rmsnorm_forward(x, weight, EPS, training=True)
    torch.cuda.synchronize()
    start = torch.cuda.Event(enable_timing=True)
    end = torch.cuda.Event(enable_timing=True)
    start.record()
    y, rstd = rmsnorm_forward(x, weight, EPS, training=True)
    end.record()
    torch.cuda.synchronize()
    t_aiter_fwd = start.elapsed_time(end)

    _ = torch_rmsnorm_ref(x_ref, weight_ref, EPS)
    torch.cuda.synchronize()
    start = torch.cuda.Event(enable_timing=True)
    end = torch.cuda.Event(enable_timing=True)
    start.record()
    ref = torch_rmsnorm_ref(x_ref, weight_ref, EPS)
    end.record()
    torch.cuda.synchronize()
    t_torch_fwd = start.elapsed_time(end)

    grad_out = torch.randn_like(y)
    torch.cuda.synchronize()
    start = torch.cuda.Event(enable_timing=True)
    end = torch.cuda.Event(enable_timing=True)
    start.record()
    dx, dweight = rmsnorm_backward_autograd(grad_out, x, rstd, weight)
    end.record()
    torch.cuda.synchronize()
    t_aiter_bwd = start.elapsed_time(end)

    torch.cuda.synchronize()
    start = torch.cuda.Event(enable_timing=True)
    end = torch.cuda.Event(enable_timing=True)
    start.record()
    ref.backward(grad_out.float())
    end.record()
    torch.cuda.synchronize()
    t_torch_bwd = start.elapsed_time(end)

    checkAllclose(
        x_ref.grad,
        dx.float(),
        atol=0.05,
        rtol=0.01,
        msg=f"[backward api dx] dim={dim}, dtype={dtype}",
    )
    checkAllclose(
        weight_ref.grad,
        dweight.float(),
        atol=0.05,
        rtol=0.01,
        msg=f"[backward api dweight] dim={dim}, dtype={dtype}",
    )
    checkAllclose(
        ref.to(dtype),
        y,
        atol=0.02,
        rtol=0.002,
        msg=f"[backward api forward] dim={dim}, dtype={dtype}",
    )
    print(f"  [timing] backward_api fwd aiter {t_aiter_fwd:.3f} / torch {t_torch_fwd:.3f} ms  |  bwd aiter {t_aiter_bwd:.3f} / torch {t_torch_bwd:.3f} ms")

    return {
        "torch_fwd": t_torch_fwd,
        "aiter_fwd": t_aiter_fwd,
        "torch_bwd": t_torch_bwd,
        "aiter_bwd": t_aiter_bwd,
    }


def test_rmsnorm_forward_autograd_inference(dtype, m, n):
    """training=False runs forward only; custom autograd does not backprop."""
    dim = (m, n)
    x = torch.randn(dim, dtype=dtype, device="cuda", requires_grad=True)
    weight = torch.randn(n, dtype=dtype, device="cuda", requires_grad=True)

    _ = rmsnorm_forward_autograd(x, weight, EPS, training=False)
    torch.cuda.synchronize()
    start = torch.cuda.Event(enable_timing=True)
    end = torch.cuda.Event(enable_timing=True)
    start.record()
    out = rmsnorm_forward_autograd(x, weight, EPS, training=False)
    end.record()
    torch.cuda.synchronize()
    t_aiter_fwd = start.elapsed_time(end)

    _ = torch_rmsnorm_ref(x.float(), weight.float(), EPS).to(dtype)
    torch.cuda.synchronize()
    start = torch.cuda.Event(enable_timing=True)
    end = torch.cuda.Event(enable_timing=True)
    start.record()
    ref = torch_rmsnorm_ref(x.float(), weight.float(), EPS).to(dtype)
    end.record()
    torch.cuda.synchronize()
    t_torch_fwd = start.elapsed_time(end)

    checkAllclose(
        ref,
        out,
        atol=0.02,
        rtol=0.002,
        msg=f"[autograd infer] dim={dim}, dtype={dtype}",
    )
    print(f"  [timing] autograd infer aiter {t_aiter_fwd:.3f} / torch {t_torch_fwd:.3f} ms")

    out.sum().backward()
    assert x.grad is None, "training=False should not populate input grad"
    assert weight.grad is None, "training=False should not populate weight grad"


l_dtype = ["fp16", "bf16"]
l_m = [1024, 2048, 4096]
l_n = [1024, 8192, 16384]

parser = argparse.ArgumentParser(
    formatter_class=argparse.RawTextHelpFormatter,
    description="Correctness tests for aiter rmsnorm_forward_autograd",
)
parser.add_argument(
    "-d",
    "--dtype",
    type=str,
    choices=l_dtype,
    nargs="?",
    default=None,
    help="Data type, e.g. -d bf16",
)
parser.add_argument("-m", "--m", type=int, nargs="?", default=None, help="M dimension")
parser.add_argument("-n", "--n", type=int, nargs="?", default=None, help="N dimension")

args = parser.parse_args()
if args.dtype is None:
    run_dtypes = [dtypes.d_dtypes[key] for key in l_dtype]
else:
    run_dtypes = [dtypes.d_dtypes[args.dtype]]
if args.m is not None:
    l_m = [args.m]
if args.n is not None:
    l_n = [args.n]

print("\nstart rmsnorm_forward_autograd correctness tests")
all_timings = []
for dtype in run_dtypes:
    for m in l_m:
        for n in l_n:
            if n < 64:
                print(f"skip dim=({m}, {n}): hidden size must be >= 64")
                continue
            print(f"\n--- dtype={dtype}, m={m}, n={n} ---")
            t1 = test_rmsnorm_forward(dtype, m, n)
            t2 = test_rmsnorm_forward_autograd(dtype, m, n)
            t3 = test_rmsnorm_backward_api(dtype, m, n)
            test_rmsnorm_forward_autograd_inference(dtype, m, n)
            all_timings.append({
                "dtype": dtype,
                "m": m,
                "n": n,
                **t1,
                **t2,
                **t3,
            })

print("\n✅ rmsnorm_forward_autograd correctness tests passed.")

# ── Timing summary ──────────────────────────────────────────────
print("\n" + "=" * 85)
print("TIMING SUMMARY — aiter vs torch (all times in ms)")
print("=" * 85)
header = (
    f"{'dtype':>6s} {'M':>5s} {'N':>5s} | "
    f"{'fwd(torch)':>10s} {'fwd(aiter)':>10s} {'speedup':>8s} | "
    f"{'bwd(torch)':>10s} {'bwd(aiter)':>10s} {'speedup':>8s}"
)
print(header)
print("-" * 85)
for t in all_timings:
    fwd_speedup = t["torch_fwd"] / t["aiter_fwd"] if t["aiter_fwd"] > 0 else 0
    bwd_speedup = t["torch_bwd"] / t["aiter_bwd"] if t.get("aiter_bwd", 0) > 0 else 0
    dtype_str = str(t["dtype"]).split(".")[-1]
    print(
        f"{dtype_str:>6s} {t['m']:5d} {t['n']:5d} | "
        f"{t['torch_fwd']:10.3f} {t['aiter_fwd']:10.3f} {fwd_speedup:7.2f}x | "
        f"{t['torch_bwd']:10.3f} {t.get('aiter_bwd', 0):10.3f} {bwd_speedup:7.2f}x"
    )
print("=" * 85)
