# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.

from __future__ import annotations

import argparse
from pathlib import Path

import torch

import aiter
from aiter.ops.triton.fla.sglang.chunk_fwd import (
    chunk_gated_delta_rule_fwd_kkt_solve as triton_kkt_solve,
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
    if not torch.allclose(actual, expected, rtol=8e-2, atol=8e-2, equal_nan=False):
        diff = (actual.float() - expected.float()).abs()
        max_abs = diff.max().item()
        mean_abs = diff.mean().item()
        raise AssertionError(
            f"Python HIP {name} mismatch, max_abs={max_abs}, mean_abs={mean_abs}"
        )
    if not torch.isfinite(actual.float()).all():
        raise AssertionError(f"Python HIP {name} contains NaN or Inf")


def make_inputs(
    *,
    dtype: torch.dtype,
    batch: int,
    seqlen: int,
    heads: int,
    grouped_heads: int,
    seed: int,
) -> tuple[torch.Tensor, torch.Tensor, torch.Tensor]:
    torch.manual_seed(seed)
    device = torch.device("cuda")
    kdim = 128
    k = (
        torch.randn((batch, seqlen, grouped_heads, kdim), device=device, dtype=dtype)
        * 0.02
    ).contiguous()
    beta = (
        torch.randn((batch, seqlen, heads), device=device, dtype=torch.float32) * 0.2
    ).contiguous()
    g = (
        torch.nn.functional.logsigmoid(
            torch.randn((batch, seqlen, heads), device=device, dtype=torch.float32)
        )
        * 0.02
    ).contiguous()
    return k, beta, g


def run_case(
    name: str,
    *,
    k: torch.Tensor,
    beta: torch.Tensor,
    g: torch.Tensor,
    cu_seqlens: torch.Tensor | None,
    chunk_indices: torch.Tensor | None,
    chunk_size: int,
) -> torch.Tensor:
    expected = triton_kkt_solve(
        k=k,
        g=g,
        beta=beta,
        cu_seqlens=cu_seqlens,
        chunk_size=chunk_size,
        chunk_indices=chunk_indices,
    )
    python_hip = aiter.chunk_gated_delta_rule_fwd_kkt_solve_hip(
        k=k,
        beta=beta,
        g=g,
        cu_seqlens=cu_seqlens,
        chunk_size=chunk_size,
        chunk_indices=chunk_indices,
    )
    torch.cuda.synchronize()
    check_close(name, python_hip, expected)
    return expected


def generate(root: Path, dtype: torch.dtype, seed: int) -> None:
    chunk_size = 64
    dense_k, dense_beta, dense_g = make_inputs(
        dtype=dtype,
        batch=2,
        seqlen=80,
        heads=4,
        grouped_heads=2,
        seed=seed,
    )
    dense_expected = run_case(
        "dense",
        k=dense_k,
        beta=dense_beta,
        g=dense_g,
        cu_seqlens=None,
        chunk_indices=None,
        chunk_size=chunk_size,
    )

    varlen_k, varlen_beta, varlen_g = make_inputs(
        dtype=dtype,
        batch=1,
        seqlen=96,
        heads=8,
        grouped_heads=4,
        seed=seed + 17,
    )
    varlen_cu_seqlens = torch.tensor([0, 31, 64, 96], device="cuda", dtype=torch.long)
    varlen_chunk_indices = prepare_chunk_indices(varlen_cu_seqlens, chunk_size).to(
        torch.long
    )
    varlen_expected = run_case(
        "varlen",
        k=varlen_k,
        beta=varlen_beta,
        g=varlen_g,
        cu_seqlens=varlen_cu_seqlens,
        chunk_indices=varlen_chunk_indices,
        chunk_size=chunk_size,
    )

    root.mkdir(parents=True, exist_ok=True)
    tensors = {
        "dense_k": dense_k,
        "dense_beta": dense_beta,
        "dense_g": dense_g,
        "dense_expected": dense_expected,
        "varlen_k": varlen_k,
        "varlen_beta": varlen_beta,
        "varlen_g": varlen_g,
        "varlen_cu_seqlens": varlen_cu_seqlens,
        "varlen_chunk_indices": varlen_chunk_indices,
        "varlen_expected": varlen_expected,
    }
    torch.jit.script(Fixture(tensors)).save(str(root / "fixture.pt"))
    print(f"Python HIP KKT-solve API passed against Triton for {dtype}")


if __name__ == "__main__":
    parser = argparse.ArgumentParser()
    parser.add_argument("fixture_dir", type=Path)
    parser.add_argument("--dtype", choices=("fp16", "bf16"), required=True)
    args = parser.parse_args()
    dtype = torch.float16 if args.dtype == "fp16" else torch.bfloat16
    generate(args.fixture_dir, dtype, 20260909)
