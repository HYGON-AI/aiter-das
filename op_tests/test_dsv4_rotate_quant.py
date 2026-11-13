# SPDX-License-Identifier: MIT
# Copyright (C) 2024-2026, Advanced Micro Devices, Inc. All rights reserved.
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
"""Tests for module_dsv4_rotate_quant: rotate_activation, rope_rotate_activation
and its fp8 variant.

Ported from the upstream op_tests/test_dsv4_rotate_quant.py, minus every fp4
path -- upstream's three fp4 entry points are not built on HCU (no e2m1
hardware), so the modes here are:

  1 rotate_activation            Hadamard only, bf16/fp16
  2 rope_rotate_activation       interleaved RoPE + Hadamard, bf16/fp16
  3 rope_rotate_activation       RoPE only (do_rotate_act=False)
  4 rope_rotate_activation_fp8quant   RoPE + Hadamard + per-1xG fp8 (gfx938/946)

The bf16 entries store through opus fp32->bf16 with this module's default
rounding (truncate, matching upstream), so the tolerance below is a relative
one that covers up to one bf16 ulp rather than bit equality.
"""

import argparse

import torch

import aiter
from aiter import dtypes
from aiter.test_common import checkAllclose, run_perftest
from aiter.jit.utils.chip_info import get_gfx

_FP8_ARCHS = ("gfx938", "gfx92a", "gfx946")


# ---------------------------------------------------------------- torch refs
def rotate_activation_torch(x: torch.Tensor) -> torch.Tensor:
    """Walsh-Hadamard transform over the last dim, normalized by 1/sqrt(n)."""
    n = x.shape[-1]
    assert n > 0 and (n & (n - 1)) == 0, f"last dim {n} must be a power of 2"

    *prefix, _ = x.shape
    flat = x.reshape(-1, n).float().contiguous()

    h = 1
    while h < n:
        view = flat.view(-1, n // (2 * h), 2, h)
        a = view[..., 0, :]
        b = view[..., 1, :]
        flat = torch.stack([a + b, a - b], dim=-2).reshape(-1, n)
        h *= 2

    flat = flat * (n**-0.5)
    return flat.reshape(*prefix, n)


def rope_torch(
    x: torch.Tensor,
    cos: torch.Tensor,
    sin: torch.Tensor,
    positions: torch.Tensor,
    rope_dim: int,
) -> torch.Tensor:
    """GPT-J style (interleaved / adjacent-pair) RoPE on the trailing rope_dim."""
    x = x.float()
    rope = x[..., -rope_dim:]
    rope_complex = torch.view_as_complex(rope.float().unflatten(-1, (-1, 2)))
    freqs = torch.complex(cos[positions].float(), sin[positions].float())
    rope_out = torch.view_as_real(rope_complex * freqs.view(-1, 1, rope_dim // 2))
    x[..., -rope_dim:] = rope_out.flatten(-2)
    return x


def rope_rotate_fp8quant_torch(x, cos, sin, positions, rope_dim, group_size=128):
    """Reference for the fused rope+hadamard+fp8 path.

    Mirrors dynamic_per_group_scaled_quant in fp32:
      absMax = max(1e-10, group_max|x|); scale = absMax / fp8_max;
      q      = round_to_nearest(x / scale). Returns (dequant, scale[m, dim/group]).
    """
    x = rope_torch(x, cos, sin, positions, rope_dim)
    x = rotate_activation_torch(x)
    fp8_max = torch.finfo(dtypes.fp8).max
    *prefix, n = x.shape
    assert n % group_size == 0
    g = n // group_size
    xf = x.float().reshape(-1, g, group_size)
    absmax = xf.abs().amax(dim=-1, keepdim=True).clamp(min=1e-10)
    scale = absmax / fp8_max
    q = (xf * scale.reciprocal()).to(dtypes.fp8)
    deq = (q.float() * scale).reshape(*prefix, n).to(x.dtype)
    return deq, scale.reshape(-1, g)


def _rope_inputs(M, dtype, rope_dim, max_pos=2048):
    positions = torch.randint(0, max_pos, (M,), dtype=torch.int64, device="cuda")
    freqs = torch.randn((max_pos, rope_dim // 2), dtype=dtypes.fp32, device="cuda")
    return positions, torch.cos(freqs).to(dtype), torch.sin(freqs).to(dtype)


# ------------------------------------------------------------------- tests
def test_rotate_activation(M, head_num, N, dtype=dtypes.bf16):
    x = torch.randn((M, head_num, N), dtype=dtype, device="cuda")
    ref = rotate_activation_torch(x.clone())

    out = torch.empty_like(x)
    _, us = run_perftest(aiter.rotate_activation, out, x)

    err = checkAllclose(ref.float(), out.float(), rtol=1e-2, atol=1e-2, msg="rotate out")
    print(
        f"[perf] rotate_activation (M={M}, head_num={head_num}, dim={N}), "
        f"dtype: {dtype}, hip avg: {us:<8.2f} us, err: {err}"
    )
    print(" [passed~]")


def test_rope_rotate_activation(
    M, head_num, N, dtype=dtypes.bf16, do_rotate_act=True, rope_dim=64
):
    x = torch.randn((M, head_num, N), dtype=dtype, device="cuda")
    positions, cos, sin = _rope_inputs(M, dtype, rope_dim)

    ref = rope_torch(x.clone(), cos, sin, positions, rope_dim)
    if do_rotate_act:
        ref = rotate_activation_torch(ref)

    out = torch.empty_like(x)
    _, us = run_perftest(
        aiter.rope_rotate_activation,
        out,
        x,
        cos,
        sin,
        positions,
        rope_dim,
        do_rotate_act=do_rotate_act,
    )

    err = checkAllclose(
        ref.float(), out.float(), rtol=1e-2, atol=1e-2, msg="rope_rotate out"
    )
    print(
        f"[perf] rope_rotate_activation (M={M}, head_num={head_num}, dim={N}, "
        f"rope_dim={rope_dim}, rotate={do_rotate_act}), dtype: {dtype}, "
        f"hip avg: {us:<8.2f} us, err: {err}"
    )
    print(" [passed~]")


def test_rope_rotate_activation_fp8quant(
    M, head_num, N, dtype=dtypes.bf16, rope_dim=64, group_size=128
):
    if get_gfx() not in _FP8_ARCHS:
        print(f"\nskip: fp8 output needs one of {_FP8_ARCHS}, running on {get_gfx()}")
        return
    x = torch.randn((M, head_num, N), dtype=dtype, device="cuda")
    positions, cos, sin = _rope_inputs(M, dtype, rope_dim)

    ref_deq, ref_scale = rope_rotate_fp8quant_torch(
        x.clone(), cos, sin, positions, rope_dim, group_size=group_size
    )

    g = N // group_size
    q_fp8 = torch.empty_like(x, dtype=dtypes.fp8)
    q_scale = torch.empty((M * head_num, g), dtype=dtypes.fp32, device="cuda")
    _, us = run_perftest(
        aiter.rope_rotate_activation,
        q_fp8,
        x,
        cos,
        sin,
        positions,
        rope_dim,
        out_scale=q_scale,
        group_size=group_size,
    )

    got_deq = (
        q_fp8.float().reshape(M * head_num, g, group_size)
        * q_scale.reshape(M * head_num, g, 1)
    ).reshape(M, head_num, N)
    err = checkAllclose(ref_deq.float(), got_deq, atol=1e-2, rtol=1e-2, msg="fp8 out")
    checkAllclose(
        ref_scale,
        q_scale.reshape(M * head_num, g),
        atol=1e-3,
        rtol=1e-3,
        msg="fp8 scale",
    )
    print(
        f"[perf] rope_rotate_activation_fp8quant (M={M}, head_num={head_num}, "
        f"dim={N}, rope_dim={rope_dim}, group_size={group_size}), dtype: {dtype}, "
        f"hip avg: {us:<8.2f} us, err: {err}"
    )
    print(" [passed~]")


if __name__ == "__main__":
    parser = argparse.ArgumentParser(
        formatter_class=argparse.RawTextHelpFormatter,
        prog="test_dsv4_rotate_quant",
        description="Test module_dsv4_rotate_quant (rotate / rope+rotate activation)",
    )
    parser.add_argument(
        "--mode",
        type=int,
        choices=[1, 2, 3, 4],
        default=2,
        help="1:rotate_activation, \n2:rope_rotate_activation (rope+hadamard), \n"
        "3:rope_rotate_activation (rope only, do_rotate_act=False), \n"
        "4:rope_rotate_activation_fp8quant (gfx938/gfx946 only)",
    )
    parser.add_argument(
        "-m",
        type=int,
        nargs="*",
        default=[1, 16, 128, 2048],
        help="M (tokens). e.g.: -m 128 2048",
    )
    parser.add_argument(
        "-hn",
        "--head_num",
        type=int,
        nargs="*",
        default=[16],
        help="head_num, must be a power of 2. e.g.: -hn 16",
    )
    parser.add_argument(
        "-n",
        "--dim",
        type=int,
        nargs="*",
        choices=[128, 256, 512, 1024],
        default=[128, 256, 512],
        help="dim (last dim). e.g.: -n 128 512",
    )
    parser.add_argument(
        "-r",
        "--rope_dim",
        type=int,
        default=64,
        help="trailing rope dim, even and divisible by the kernel vec_size",
    )
    parser.add_argument(
        "-d",
        "--dtype",
        type=lambda v: dtypes.d_dtypes[v],
        nargs="*",
        default=[dtypes.bf16],
        help="input dtype: bf16 | fp16",
    )
    args = parser.parse_args()

    for dtype in args.dtype:
        for head_num in args.head_num:
            for dim in args.dim:
                for m in args.m:
                    if args.mode == 1:
                        test_rotate_activation(m, head_num, dim, dtype=dtype)
                    elif args.mode == 2:
                        test_rope_rotate_activation(
                            m,
                            head_num,
                            dim,
                            dtype=dtype,
                            do_rotate_act=True,
                            rope_dim=args.rope_dim,
                        )
                    elif args.mode == 3:
                        test_rope_rotate_activation(
                            m,
                            head_num,
                            dim,
                            dtype=dtype,
                            do_rotate_act=False,
                            rope_dim=args.rope_dim,
                        )
                    elif args.mode == 4:
                        test_rope_rotate_activation_fp8quant(
                            m, head_num, dim, dtype=dtype, rope_dim=args.rope_dim
                        )
