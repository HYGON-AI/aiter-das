# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.

import torch
import aiter
import pytest
import torch.nn as nn
import torch.nn.functional as F
from aiter.test_common import checkAllclose, perftest, benchmark

def precompute_freqs_complex(dim: int, seq_len: int, theta: float = 10000.0, device="cuda"):
    freqs = 1.0 / (theta ** (torch.arange(0, dim, 2, device = device)[: (dim // 2)].float() / dim))
    t = torch.arange(seq_len, device=freqs.device)
    freqs = torch.outer(t, freqs).float()
    freqs_cis = torch.polar(torch.ones_like(freqs), freqs)
    return freqs_cis


def apply_rotary_emb_qwen(
    x: torch.Tensor,
    freqs_cis: torch.Tensor,
    sp_rank: int = 0,
    sp_size: int = 1,
) -> torch.Tensor:
    x_rotated = torch.view_as_complex(x.float().reshape(*x.shape[:-1], -1, 2))
    batch, local_seq_len, head, headdim = x.shape
    if freqs_cis.shape[0] < local_seq_len:
        k = freqs_cis.ndim
        n = local_seq_len - freqs_cis.shape[0]
        pad_config = [0, 0] * (k - 1) + [0, n]
        freqs_cis = F.pad(freqs_cis, pad_config, value=0)
    if sp_size > 1:
        start = sp_rank * local_seq_len
        end = (sp_rank + 1) * local_seq_len
        if len(freqs_cis) < end:
            raise ValueError(
                f"The length of freqs_cis ({len(freqs_cis)}) is less than the specified end value ({end}). "
                "Ensure freqs_cis has enough elements."
            )
        freqs_rank = freqs_cis[start:end]
        if freqs_rank.shape[0] != local_seq_len:
            raise ValueError(f"freqs slice length {freqs_rank.shape[0]} != local_seq_len {local_seq_len}, ")
    else:
        freqs_rank = freqs_cis[:local_seq_len]
    freqs_rank = freqs_rank.unsqueeze(1)
    x_out = torch.view_as_real(x_rotated * freqs_rank).flatten(3)
    return x_out.type_as(x)

def prepare_img_q(img_q: torch.Tensor, img_freqs: torch.Tensor, q_norm_weight: torch.Tensor, num_heads) -> torch.Tensor:
    temp_img_q = img_q.unflatten(-1, (num_heads, -1))
    rmsnorm = nn.RMSNorm(normalized_shape=head_dim, eps=1e-6, elementwise_affine=False).cuda()
    temp_img_q = rmsnorm(temp_img_q) * q_norm_weight
    temp_img_q = apply_rotary_emb_qwen(temp_img_q, img_freqs)
    return temp_img_q

def prepare_img_q_opt(img_q: torch.Tensor, img_freqs: torch.Tensor, q_norm_weight: torch.Tensor, num_heads) -> torch.Tensor:
    temp_img_q = img_q.unflatten(-1, (num_heads, -1))
    temp_ima_freqs = torch.view_as_real(img_freqs).flatten(1)
    output=torch.empty_like(temp_img_q)
    aiter.fused_rmsnorm_rope(temp_img_q, q_norm_weight, temp_ima_freqs, output)
    return output


def fused_rmsnorm_rope_reference(x, weight, freqs, eps=1e-6):
    # Match the fused kernel: all normalization, scaling, and rotation math is
    # FP32, with a single conversion to BF16 for the final output.
    x_float = x.float()
    normalized = x_float * torch.rsqrt(x_float.square().mean(-1, keepdim=True) + eps)
    normalized = normalized * weight.float()
    normalized_complex = torch.view_as_complex(
        normalized.float().reshape(*normalized.shape[:-1], -1, 2)
    )
    freqs_complex = torch.view_as_complex(freqs.reshape(freqs.shape[0], -1, 2))
    return torch.view_as_real(
        normalized_complex * freqs_complex[: x.shape[1], None]
    ).flatten(-2).to(x.dtype)


@pytest.mark.parametrize("batch", [1, 2])
@pytest.mark.parametrize("seq_len", [256, 4128])
@torch.inference_mode()
def test_fused_rmsnorm_rope_custom_op_compile(batch, seq_len):
    if not torch.cuda.is_available():
        pytest.skip("CUDA is not available")

    torch.manual_seed(0)
    x = torch.randn(
        batch, seq_len, 24, 128, device="cuda", dtype=torch.bfloat16
    )
    weight = torch.randn(128, device="cuda", dtype=torch.bfloat16).detach()
    freqs = torch.view_as_real(
        precompute_freqs_complex(128, seq_len, device="cuda")
    ).flatten(1).contiguous()

    def fn(x, weight, freqs):
        return torch.ops.aiter.fused_rmsnorm_rope(x, weight, freqs, 1e-6)

    eager_output = aiter.fused_rmsnorm_rope_op(x, weight, freqs)
    expected = fused_rmsnorm_rope_reference(x, weight, freqs)
    torch.testing.assert_close(eager_output, expected, atol=0.02, rtol=0.02)

    compiled_fn = torch.compile(fn, fullgraph=True, dynamic=False)
    compiled_output = compiled_fn(x, weight, freqs)
    torch.testing.assert_close(compiled_output, eager_output, atol=0.02, rtol=0.02)

    exported = torch._dynamo.export(fn)(x, weight, freqs)[0]
    assert any(
        node.target == torch.ops.aiter.fused_rmsnorm_rope
        for node in exported.graph.nodes
    )


@torch.inference_mode()
def test_fused_rmsnorm_rope_custom_op_strided_qkv_view():
    if not torch.cuda.is_available():
        pytest.skip("CUDA is not available")

    torch.manual_seed(0)
    batch, seq_len, num_heads, head_dim = 2, 256, 24, 128
    fused_qkv = torch.randn(
        batch,
        seq_len,
        3 * num_heads * head_dim,
        device="cuda",
        dtype=torch.bfloat16,
    )
    q = fused_qkv.chunk(3, dim=-1)[0].unflatten(-1, (num_heads, head_dim))
    assert not q.is_contiguous() and q.stride(-1) == 1

    weight = torch.randn(head_dim, device="cuda", dtype=torch.bfloat16).detach()
    freqs = torch.view_as_real(
        precompute_freqs_complex(head_dim, seq_len, device="cuda")
    ).flatten(1).contiguous()
    output = aiter.fused_rmsnorm_rope_op(q, weight, freqs)
    legacy_output = torch.empty_like(q)
    aiter.fused_rmsnorm_rope(q, weight, freqs, legacy_output)
    expected = fused_rmsnorm_rope_reference(q, weight, freqs)
    torch.testing.assert_close(output, expected, atol=0.02, rtol=0.02)
    torch.testing.assert_close(legacy_output, output, atol=0.02, rtol=0.02)


@pytest.mark.parametrize("batch", [1, 2])
@pytest.mark.parametrize("seq_len", [256, 4128])
@torch.inference_mode()
def test_fused_qk_rmsnorm_rope_custom_op_compile(batch, seq_len):
    if not torch.cuda.is_available():
        pytest.skip("CUDA is not available")

    torch.manual_seed(0)
    q = torch.randn(
        batch, seq_len, 24, 128, device="cuda", dtype=torch.bfloat16
    )
    k = torch.randn_like(q)
    q_weight = torch.randn(128, device="cuda", dtype=torch.bfloat16).detach()
    k_weight = torch.randn(128, device="cuda", dtype=torch.bfloat16).detach()
    freqs = torch.view_as_real(
        precompute_freqs_complex(128, seq_len, device="cuda")
    ).flatten(1).contiguous()

    def fn(q, k, q_weight, k_weight, freqs):
        return torch.ops.aiter.fused_qk_rmsnorm_rope(
            q, k, q_weight, k_weight, freqs, 1e-6
        )

    q_output, k_output = aiter.fused_qk_rmsnorm_rope(
        q, k, q_weight, k_weight, freqs
    )
    q_expected = fused_rmsnorm_rope_reference(q, q_weight, freqs)
    k_expected = fused_rmsnorm_rope_reference(k, k_weight, freqs)
    torch.testing.assert_close(q_output, q_expected, atol=0.02, rtol=0.02)
    torch.testing.assert_close(k_output, k_expected, atol=0.02, rtol=0.02)

    compiled_fn = torch.compile(fn, fullgraph=True, dynamic=False)
    compiled_q, compiled_k = compiled_fn(q, k, q_weight, k_weight, freqs)
    torch.testing.assert_close(compiled_q, q_output, atol=0.02, rtol=0.02)
    torch.testing.assert_close(compiled_k, k_output, atol=0.02, rtol=0.02)

    exported = torch._dynamo.export(fn)(q, k, q_weight, k_weight, freqs)[0]
    assert any(
        node.target == torch.ops.aiter.fused_qk_rmsnorm_rope
        for node in exported.graph.nodes
    )


@torch.inference_mode()
def test_fused_qk_rmsnorm_rope_custom_op_strided_qkv_views():
    if not torch.cuda.is_available():
        pytest.skip("CUDA is not available")

    torch.manual_seed(0)
    batch, seq_len, num_heads, head_dim = 2, 256, 24, 128
    fused_qkv = torch.randn(
        batch,
        seq_len,
        3 * num_heads * head_dim,
        device="cuda",
        dtype=torch.bfloat16,
    )
    q, k, _ = (
        tensor.unflatten(-1, (num_heads, head_dim))
        for tensor in fused_qkv.chunk(3, dim=-1)
    )
    assert not q.is_contiguous() and q.stride(-1) == 1
    assert not k.is_contiguous() and k.stride(-1) == 1

    q_weight = torch.randn(head_dim, device="cuda", dtype=torch.bfloat16).detach()
    k_weight = torch.randn(head_dim, device="cuda", dtype=torch.bfloat16).detach()
    freqs = torch.view_as_real(
        precompute_freqs_complex(head_dim, seq_len, device="cuda")
    ).flatten(1).contiguous()
    q_output, k_output = aiter.fused_qk_rmsnorm_rope(
        q, k, q_weight, k_weight, freqs
    )
    torch.testing.assert_close(
        q_output,
        fused_rmsnorm_rope_reference(q, q_weight, freqs),
        atol=0.02,
        rtol=0.02,
    )
    torch.testing.assert_close(
        k_output,
        fused_rmsnorm_rope_reference(k, k_weight, freqs),
        atol=0.02,
        rtol=0.02,
    )


if __name__ == "__main__":
    batch, seq_len, num_head, head_dim = 2, 12288, 24, 128
    img_q = (-2 * torch.rand((batch, seq_len, num_head * head_dim), dtype=torch.bfloat16).cuda() + 1) / 50
    norm_q_weight = (-2 * torch.rand((head_dim), dtype=torch.bfloat16).cuda() + 1) / 50
    img_freqs = precompute_freqs_complex(head_dim, seq_len)
    
    torch_out = prepare_img_q(img_q, img_freqs, norm_q_weight, num_head)
    opt_output = prepare_img_q_opt(img_q, img_freqs, norm_q_weight, num_head)

    # print("torch_out: ",torch_out, torch_out.dtype, torch_out.shape)
    # print("opt_output: ",opt_output, opt_output.dtype, opt_output.shape)
    checkAllclose(torch_out, opt_output, rtol=1e-2, atol=1e-2)
