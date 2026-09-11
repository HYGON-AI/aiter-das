# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.

from __future__ import annotations

import argparse
from pathlib import Path

import torch

import aiter
from aiter.ops.triton.fla.fused_sigmoid_gating import (
    fused_sigmoid_gating_delta_rule_update as triton_fused_sigmoid_gating_delta_rule_update,
)


RTOL = 5e-2
ATOL = 5e-2


class Fixture(torch.nn.Module):
    def __init__(self, tensors: dict[str, torch.Tensor]) -> None:
        super().__init__()
        for name, tensor in tensors.items():
            self.register_buffer(name, tensor)

    def forward(self, value: torch.Tensor) -> torch.Tensor:
        return value


def check_close(name: str, actual: torch.Tensor, expected: torch.Tensor) -> None:
    actual_f = actual.float()
    expected_f = expected.float()
    if not torch.allclose(actual_f, expected_f, rtol=RTOL, atol=ATOL, equal_nan=True):
        max_abs = (actual_f - expected_f).abs().max().item()
        raise AssertionError(f"Python HIP {name} mismatch, max_abs={max_abs}")


def randn(shape: tuple[int, ...], dtype: torch.dtype, scale: float) -> torch.Tensor:
    return (torch.randn(shape, device="cuda", dtype=dtype) * scale).contiguous()


def run_case(
    prefix: str,
    tensors: dict[str, torch.Tensor],
    *,
    dtype: torch.dtype,
    num_reqs: int,
    seq_len: int,
    heads: int,
    value_heads: int,
    k_dim: int,
    v_dim: int,
    speculative: bool,
) -> None:
    num_tokens = num_reqs * seq_len
    state_rows = num_tokens + 4

    A_log = randn((value_heads,), torch.float32, 0.05)
    a = randn((num_tokens, value_heads), dtype, 0.1)
    b = randn((num_tokens, value_heads), dtype, 0.1)
    dt_bias = randn((value_heads,), dtype, 0.05)
    q = randn((1, num_tokens, heads, k_dim), dtype, 0.2)
    k = randn((1, num_tokens, heads, k_dim), dtype, 0.2)
    v = randn((1, num_tokens, value_heads, v_dim), dtype, 0.2)
    initial_state = randn((state_rows, value_heads, v_dim, k_dim), torch.float32, 0.02)
    cu_seqlens = torch.arange(
        0,
        num_tokens + 1,
        seq_len,
        device="cuda",
        dtype=torch.int32,
    ).contiguous()

    if speculative:
        ssm_state_indices = torch.randperm(state_rows, device="cuda", dtype=torch.int64)[
            :num_tokens
        ].to(torch.int32)
        ssm_state_indices = ssm_state_indices.view(num_reqs, seq_len).contiguous()
        num_accepted_tokens = torch.tensor(
            [1, min(3, seq_len)],
            device="cuda",
            dtype=torch.int32,
        )[:num_reqs].contiguous()
    else:
        ssm_state_indices = torch.randperm(state_rows, device="cuda", dtype=torch.int64)[
            :num_reqs
        ].to(torch.int32).contiguous()
        num_accepted_tokens = None

    expected_state = initial_state.clone()
    expected_out, expected_final_state = triton_fused_sigmoid_gating_delta_rule_update(
        A_log=A_log,
        a=a,
        b=b,
        dt_bias=dt_bias,
        q=q,
        k=k,
        v=v,
        initial_state=expected_state,
        inplace_final_state=True,
        cu_seqlens=cu_seqlens,
        ssm_state_indices=ssm_state_indices,
        num_accepted_tokens=num_accepted_tokens,
        use_qk_l2norm_in_kernel=True,
    )

    hip_state = initial_state.clone()
    hip_out, hip_final_state = aiter.vllm_fused_sigmoid_gating_delta_rule_update(
        A_log=A_log,
        a=a,
        b=b,
        dt_bias=dt_bias,
        q=q,
        k=k,
        v=v,
        initial_state=hip_state,
        inplace_final_state=True,
        cu_seqlens=cu_seqlens,
        ssm_state_indices=ssm_state_indices,
        num_accepted_tokens=num_accepted_tokens,
        use_qk_l2norm_in_kernel=True,
    )
    torch.cuda.synchronize()

    check_close(f"{prefix}_out", hip_out, expected_out)
    check_close(f"{prefix}_final_state", hip_final_state, expected_final_state)
    check_close(f"{prefix}_inplace_state", hip_state, expected_final_state)

    case_tensors = {
        "A_log": A_log,
        "a": a,
        "b": b,
        "dt_bias": dt_bias,
        "q": q,
        "k": k,
        "v": v,
        "initial_state": initial_state,
        "cu_seqlens": cu_seqlens,
        "ssm_state_indices": ssm_state_indices,
        "expected_out": expected_out,
        "expected_final_state": expected_final_state,
    }
    if num_accepted_tokens is not None:
        case_tensors["num_accepted_tokens"] = num_accepted_tokens

    for name, tensor in case_tensors.items():
        tensors[f"{prefix}_{name}"] = tensor


def generate(root: Path, dtype: torch.dtype, seed: int) -> None:
    torch.manual_seed(seed)
    tensors: dict[str, torch.Tensor] = {}

    run_case(
        "decode",
        tensors,
        dtype=dtype,
        num_reqs=3,
        seq_len=1,
        heads=2,
        value_heads=4,
        k_dim=128,
        v_dim=128,
        speculative=False,
    )
    run_case(
        "spec",
        tensors,
        dtype=dtype,
        num_reqs=2,
        seq_len=4,
        heads=2,
        value_heads=4,
        k_dim=128,
        v_dim=128,
        speculative=True,
    )

    root.mkdir(parents=True, exist_ok=True)
    torch.jit.script(Fixture(tensors)).save(str(root / "fixture.pt"))
    print(f"Python HIP API passed against Triton for {dtype}")


if __name__ == "__main__":
    parser = argparse.ArgumentParser()
    parser.add_argument("fixture_dir", type=Path)
    parser.add_argument("--dtype", choices=("fp16", "bf16"), required=True)
    args = parser.parse_args()
    dtype = torch.float16 if args.dtype == "fp16" else torch.bfloat16
    generate(args.fixture_dir, dtype, 20260727)
