# Copyright (c) 2026 Hygon Information Technology Co., Ltd.

import argparse
import time
import torch
import torch.nn.functional as F
from aiter.test_common import checkAllclose
from aiter.ops.fuse_rms_mrope import fuse_rms_mrope

import os

if "CUDA_VISIBLE_DEVICES" not in os.environ:
    os.environ["CUDA_VISIBLE_DEVICES"] = "0"

torch.set_default_device("cuda")


def apply_mrope_torch(
    x: torch.Tensor,
    cos: torch.Tensor,
    sin: torch.Tensor,
    mrope_section: list,
    is_interleaved: bool,
) -> torch.Tensor:
    """Vectorized reference M-RoPE implemented in PyTorch.

    x:          [num_tokens, num_heads, head_size]
    cos/sin:    [3, num_tokens, half_rd]
    """
    half_rd = cos.shape[-1]
    t, h, w = mrope_section

    pos = torch.arange(half_rd, device=x.device)
    if is_interleaved:
        is_h = ((pos % 3) == 1) & (pos <= 3 * h)
        is_w = ((pos % 3) == 2) & (pos <= 3 * w)
    else:
        is_h = (pos >= t) & (pos < t + h)
        is_w = (pos >= t + h) & (pos < half_rd)

    c = torch.where(is_h, cos[1], torch.where(is_w, cos[2], cos[0]))[:, None, :]
    s = torch.where(is_h, sin[1], torch.where(is_w, sin[2], sin[0]))[:, None, :]

    x0 = x[:, :, :half_rd]
    x1 = x[:, :, half_rd:]
    x_rot = x.clone()
    x_rot[:, :, :half_rd] = x0 * c - x1 * s
    x_rot[:, :, half_rd:] = x1 * c + x0 * s
    return x_rot


def ref_fuse_rms_mrope(
    q: torch.Tensor,
    k: torch.Tensor,
    cos: torch.Tensor,
    sin: torch.Tensor,
    mrope_section: list,
    head_size: int,
    is_interleaved: bool,
    weight_q: torch.Tensor,
    weight_k: torch.Tensor,
    residual_q: torch.Tensor | None,
    residual_k: torch.Tensor | None,
    epsilon: float,
) -> tuple[torch.Tensor, torch.Tensor]:
    num_tokens = q.shape[0]
    n_qh = q.shape[1] // head_size
    n_kh = k.shape[1] // head_size

    q2 = q.view(num_tokens, n_qh, head_size).float()
    k2 = k.view(num_tokens, n_kh, head_size).float()

    if residual_q is not None:
        q2 = q2 + residual_q.view(num_tokens, n_qh, head_size).float()
    if residual_k is not None:
        k2 = k2 + residual_k.view(num_tokens, n_kh, head_size).float()

    wq = weight_q.float().view(1, 1, head_size)
    wk = weight_k.float().view(1, 1, head_size)

    q_rms = q2 * torch.rsqrt(q2.pow(2).mean(dim=-1, keepdim=True) + epsilon) * wq
    k_rms = k2 * torch.rsqrt(k2.pow(2).mean(dim=-1, keepdim=True) + epsilon) * wk

    q_out = apply_mrope_torch(q_rms, cos, sin, mrope_section, is_interleaved)
    k_out = apply_mrope_torch(k_rms, cos, sin, mrope_section, is_interleaved)

    return q_out.view_as(q).to(q.dtype), k_out.view_as(k).to(k.dtype)


def run_test(
    num_tokens: int,
    n_qh: int,
    n_kh: int,
    head_size: int,
    mrope_section: list,
    is_interleaved: bool,
    dtype: torch.dtype,
    use_residual: bool,
    epsilon: float = 1e-6,
    warmup: int = 3,
    iters: int = 10,
) -> dict:
    half_rd = head_size // 2

    q = torch.randn(num_tokens, n_qh * head_size, dtype=dtype).cuda()
    k = torch.randn(num_tokens, n_kh * head_size, dtype=dtype).cuda()
    cos = torch.randn(3, num_tokens, half_rd, dtype=dtype).cuda()
    sin = torch.randn(3, num_tokens, half_rd, dtype=dtype).cuda()
    weight_q = torch.randn(head_size, dtype=dtype).cuda()
    weight_k = torch.randn(head_size, dtype=dtype).cuda()

    residual_q = None
    residual_k = None
    if use_residual:
        residual_q = torch.randn_like(q)
        residual_k = torch.randn_like(k)

    q_ref, k_ref = ref_fuse_rms_mrope(
        q, k, cos, sin, mrope_section, head_size,
        is_interleaved, weight_q, weight_k, residual_q, residual_k, epsilon
    )

    q_opt = q.clone()
    k_opt = k.clone()
    if residual_q is not None:
        residual_q_opt = residual_q.clone()
        residual_k_opt = residual_k.clone()
    else:
        residual_q_opt = None
        residual_k_opt = None

    fuse_rms_mrope(
        q_opt, k_opt, cos, sin, mrope_section, head_size,
        is_interleaved, weight_q, weight_k, residual_q_opt, residual_k_opt, epsilon
    )

    q_err = checkAllclose(q_ref, q_opt, rtol=5e-2, atol=5e-2)
    k_err = checkAllclose(k_ref, k_opt, rtol=5e-2, atol=5e-2)
    if q_err > 0.05 or k_err > 0.05:
        raise AssertionError(f"checkAllclose failed: q_err={q_err}, k_err={k_err}")

    def run_kernel():
        fuse_rms_mrope(
            q_opt, k_opt, cos, sin, mrope_section, head_size,
            is_interleaved, weight_q, weight_k, residual_q_opt, residual_k_opt, epsilon
        )

    def run_ref():
        return ref_fuse_rms_mrope(
            q, k, cos, sin, mrope_section, head_size,
            is_interleaved, weight_q, weight_k, residual_q, residual_k, epsilon
        )

    for _ in range(warmup):
        run_kernel()
    torch.cuda.synchronize()
    t0 = time.perf_counter()
    for _ in range(iters):
        run_kernel()
    torch.cuda.synchronize()
    kernel_ms = (time.perf_counter() - t0) / iters * 1000.0

    for _ in range(warmup):
        run_ref()
    torch.cuda.synchronize()
    t0 = time.perf_counter()
    for _ in range(iters):
        run_ref()
    torch.cuda.synchronize()
    ref_ms = (time.perf_counter() - t0) / iters * 1000.0

    return {
        "num_tokens": num_tokens,
        "n_qh": n_qh,
        "n_kh": n_kh,
        "head_size": head_size,
        "is_interleaved": is_interleaved,
        "residual": use_residual,
        "kernel_ms": kernel_ms,
        "ref_ms": ref_ms,
    }


if __name__ == "__main__":
    parser = argparse.ArgumentParser()
    parser.add_argument("--num_tokens", type=int, default=128)
    parser.add_argument("--head_size", type=int, default=128)
    parser.add_argument("--dtype", type=str, default="bf16")
    parser.add_argument("--residual", action="store_true")
    args = parser.parse_args()

    dtype = torch.bfloat16 if args.dtype == "bf16" else torch.float16

    half_rd = args.head_size // 2
    mrope_section = [half_rd // 2, half_rd // 4, half_rd - half_rd // 2 - half_rd // 4]

    test_cases = [
        (args.num_tokens, 8, 8, args.head_size, mrope_section, False),
        (args.num_tokens, 8, 4, args.head_size, mrope_section, False),
        (args.num_tokens, 6, 1, args.head_size, mrope_section, False),
        (args.num_tokens, 4, 1, args.head_size, mrope_section, False),
        (args.num_tokens, 8, 8, args.head_size, mrope_section, True),
        (args.num_tokens, 8, 4, args.head_size, mrope_section, True),
        (args.num_tokens, 6, 1, args.head_size, mrope_section, True),
        (args.num_tokens, 4, 1, args.head_size, mrope_section, True),
    ]

    results = []
    for num_tokens, n_qh, n_kh, head_size, mrope_section, is_interleaved in test_cases:
        print(
            f"Testing num_tokens={num_tokens}, n_qh={n_qh}, n_kh={n_kh}, "
            f"head_size={head_size}, mrope_section={mrope_section}, "
            f"is_interleaved={is_interleaved}, residual={args.residual}"
        )
        result = run_test(
            num_tokens, n_qh, n_kh, head_size, mrope_section,
            is_interleaved, dtype, args.residual
        )
        results.append(result)
        print("PASSED")

    print("\n" + "=" * 100)
    print(f"{'Case':<60} {'Kernel(ms)':>12} {'Ref(ms)':>12} {'Speedup':>12}")
    print("-" * 100)
    for r in results:
        case = (
            f"nt={r['num_tokens']}, nq={r['n_qh']}, nk={r['n_kh']}, "
            f"hd={r['head_size']}, interleaved={r['is_interleaved']}, residual={r['residual']}"
        )
        speedup = r["ref_ms"] / r["kernel_ms"] if r["kernel_ms"] > 0 else float("inf")
        print(f"{case:<50} {r['kernel_ms']:>12.3f} {r['ref_ms']:>12.3f} {speedup:>12.2f}x")
    print("=" * 100)
