# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.

from __future__ import annotations

import argparse
from pathlib import Path

import torch

import aiter
from aiter.ops.triton.fla.vllm.chunk_o import (
    chunk_fwd_o as triton_chunk_fwd_o,
    prepare_chunk_indices,
)


class Fixture(torch.nn.Module):
    def __init__(self, tensors: dict[str, torch.Tensor]) -> None:
        super().__init__()
        for name, tensor in tensors.items():
            self.register_buffer(name, tensor)

    def forward(self, value: torch.Tensor) -> torch.Tensor:
        return value


def check_close(name: str, actual: torch.Tensor, expected: torch.Tensor) -> None:
    if not torch.allclose(actual, expected, rtol=8e-2, atol=8e-2, equal_nan=True):
        max_abs = (actual.float() - expected.float()).abs().max().item()
        raise AssertionError(f"Python HIP {name} mismatch, max_abs={max_abs}")


def generate(root: Path, dtype: torch.dtype, seed: int) -> None:
    torch.manual_seed(seed)
    device = torch.device("cuda")
    # Keep the external-link test quick while crossing a chunk boundary.
    b, t, hg, h, kdim, vdim, chunk_size = 1, 65, 2, 4, 128, 128, 64
    cu_seqlens = torch.tensor([0, t], device=device, dtype=torch.long)
    chunk_indices = prepare_chunk_indices(cu_seqlens, chunk_size)
    n_chunks = int(chunk_indices.shape[0])

    q = (torch.randn((b, t, hg, kdim), device=device, dtype=dtype) * 0.01).contiguous()
    k = (torch.randn((b, t, hg, kdim), device=device, dtype=dtype) * 0.01).contiguous()
    v = (torch.randn((b, t, h, vdim), device=device, dtype=dtype) * 0.01).contiguous()
    h_state = (
        torch.randn((b, n_chunks, h, vdim, kdim), device=device, dtype=dtype) * 0.01
    ).contiguous()
    g = (torch.randn((b, t, h), device=device, dtype=torch.float32) * 0.01).contiguous()
    g_gamma = (torch.randn((h,), device=device, dtype=torch.float32) * 0.01).contiguous()
    scale = kdim ** -0.5

    kwargs = dict(
        g=g,
        g_gamma=g_gamma,
        scale=scale,
        cu_seqlens=cu_seqlens,
        chunk_size=chunk_size,
        chunk_indices=chunk_indices,
        use_exp2=False,
        transpose_state_layout=True,
    )
    expected_o = triton_chunk_fwd_o(q=q, k=k, v=v, h=h_state, **kwargs)
    python_hip_o = aiter.chunk_fwd_o_vllm_hip_blockdim64(
        q=q,
        k=k,
        v=v,
        h=h_state,
        **kwargs,
    )
    torch.cuda.synchronize()
    check_close("o", python_hip_o, expected_o)

    root.mkdir(parents=True, exist_ok=True)
    tensors = {
        "q": q,
        "k": k,
        "v": v,
        "h": h_state,
        "g": g,
        "g_gamma": g_gamma,
        "cu_seqlens": cu_seqlens,
        "chunk_indices": chunk_indices,
        "expected_o": expected_o,
    }
    torch.jit.script(Fixture(tensors)).save(str(root / "fixture.pt"))
    print(f"Python HIP chunk_fwd_o API passed against Triton for {dtype}")


if __name__ == "__main__":
    parser = argparse.ArgumentParser()
    parser.add_argument("fixture_dir", type=Path)
    parser.add_argument("--dtype", choices=("fp16", "bf16"), required=True)
    args = parser.parse_args()
    dtype = torch.float16 if args.dtype == "fp16" else torch.bfloat16
    generate(args.fixture_dir, dtype, 20260827)
