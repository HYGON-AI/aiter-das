# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.

from __future__ import annotations

import argparse
from pathlib import Path

import torch

import aiter
from aiter.ops.triton.fla.vllm.chunk_delta_h import (
    chunk_gated_delta_rule_fwd_h as triton_chunk_gated_delta_rule_fwd_h,
)
from aiter.ops.triton.fla.sglang.chunk_delta_h import (
    chunk_gated_delta_rule_fwd_h as triton_chunk_gated_delta_rule_fwd_h_sglang,
)


class Fixture(torch.nn.Module):
    def __init__(self, tensors: dict[str, torch.Tensor]) -> None:
        super().__init__()
        for name, tensor in tensors.items():
            self.register_buffer(name, tensor)

    def forward(self, value: torch.Tensor) -> torch.Tensor:
        return value


def check_close(name: str, actual: torch.Tensor, expected: torch.Tensor) -> None:
    if not torch.allclose(actual, expected, rtol=2e-2, atol=2e-2, equal_nan=True):
        max_abs = (actual.float() - expected.float()).abs().max().item()
        raise AssertionError(f"Python HIP {name} mismatch, max_abs={max_abs}")


def generate(root: Path, dtype: torch.dtype, seed: int) -> None:
    torch.manual_seed(seed)
    device = torch.device("cuda")
    # Keep the external-link test quick while crossing a chunk boundary.
    b, t, hg, h, kdim, vdim = 1, 65, 1, 2, 128, 128
    k = (torch.randn((b, t, hg, kdim), device=device, dtype=dtype) * 0.2).contiguous()
    w = (torch.randn((b, t, h, kdim), device=device, dtype=dtype) * 0.2).contiguous()
    u = (torch.randn((b, t, h, vdim), device=device, dtype=dtype) * 0.2).contiguous()
    g = (torch.randn((b, t, h), device=device, dtype=torch.float32) * 0.05).contiguous()
    initial_state = (
        torch.randn((b, h, vdim, kdim), device=device, dtype=torch.float32) * 0.02
    ).contiguous()
    initial_state_indices = torch.arange(b, device=device, dtype=torch.int32)

    kwargs = dict(
        g=g,
        gk=None,
        initial_state=initial_state,
        initial_state_indices=initial_state_indices,
        output_final_state=True,
        chunk_size=64,
        save_new_value=True,
        cu_seqlens=None,
        chunk_indices=None,
        use_exp2=False,
        transpose_state_layout=True,
    )
    expected = triton_chunk_gated_delta_rule_fwd_h(k=k, w=w, u=u, **kwargs)
    python_hip = aiter.chunk_gated_delta_rule_fwd(k=k, w=w, u=u, **kwargs)
    torch.cuda.synchronize()
    for name, actual, reference in zip(("h", "v_new", "final_state"), python_hip, expected):
        check_close(name, actual, reference)

    sglang_initial_state = initial_state.clone()
    expected_sglang_state = sglang_initial_state.clone()
    expected_sglang = triton_chunk_gated_delta_rule_fwd_h_sglang(
        k=k,
        w=w,
        u=u,
        **{**kwargs, "initial_state": expected_sglang_state},
    )
    python_sglang_state = sglang_initial_state.clone()
    python_sglang = aiter.chunk_gated_delta_rule_fwd_sglang(
        k=k,
        w=w,
        u=u,
        **{**kwargs, "initial_state": python_sglang_state},
    )
    torch.cuda.synchronize()
    for name, actual, reference in zip(("sglang_h", "sglang_v_new"), python_sglang, expected_sglang):
        check_close(name, actual, reference)
    check_close("sglang_state", python_sglang_state, expected_sglang_state)

    root.mkdir(parents=True, exist_ok=True)
    tensors = {
        "k": k,
        "w": w,
        "u": u,
        "g": g,
        "initial_state": initial_state,
        "initial_state_indices": initial_state_indices,
        "expected_h": expected[0],
        "expected_v_new": expected[1],
        "expected_final_state": expected[2],
        "sglang_initial_state": sglang_initial_state,
        "expected_sglang_h": expected_sglang[0],
        "expected_sglang_v_new": expected_sglang[1],
        "expected_sglang_state": expected_sglang_state,
    }
    torch.jit.script(Fixture(tensors)).save(str(root / "fixture.pt"))
    print(f"Python HIP API passed against Triton for {dtype}")


if __name__ == "__main__":
    parser = argparse.ArgumentParser()
    parser.add_argument("fixture_dir", type=Path)
    parser.add_argument("--dtype", choices=("fp16", "bf16"), required=True)
    args = parser.parse_args()
    dtype = torch.float16 if args.dtype == "fp16" else torch.bfloat16
    generate(args.fixture_dir, dtype, 20260710)
