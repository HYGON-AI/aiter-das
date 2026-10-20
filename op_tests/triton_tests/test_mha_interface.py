# SPDX-License-Identifier: MIT

import importlib
import json

import pytest
import torch

from aiter import flash_attn_func, flash_attn_varlen_func


mha = importlib.import_module("aiter.ops.triton.mha")


def test_public_mha_exports():
    assert flash_attn_func is mha.flash_attn_func
    assert flash_attn_varlen_func is mha.flash_attn_varlen_func


@pytest.fixture
def config_dir(monkeypatch, tmp_path):
    monkeypatch.setattr(mha, "AITER_TRITON_CONFIGS_PATH", str(tmp_path))
    mha._load_default_config.cache_clear()
    yield tmp_path
    mha._load_default_config.cache_clear()


@pytest.mark.parametrize(
    "dropout,dtype,block_m",
    [
        (False, torch.float16, 128),
        (False, torch.bfloat16, 128),
        (True, torch.float16, 32),
        (False, torch.float32, 32),
    ],
)
def test_missing_mha_config_uses_baseline(
    config_dir, monkeypatch, dropout, dtype, block_m
):
    monkeypatch.setattr(mha.arch_info, "get_device", lambda: "missing")
    for _ in range(2):
        config = mha._get_config(dropout, dtype)
        assert config["BLOCK_M"] == block_m
        assert config["num_stages"] == 1


def test_mha_config_cache_is_device_specific(config_dir, monkeypatch):
    for device, block_m in (("gfx936", 64), ("gfx938", 128)):
        (config_dir / f"{device}-MHA-DEFAULT.json").write_text(
            json.dumps({"fwd": {"default": {"BLOCK_M": block_m}}})
        )
    for device, block_m in (("gfx936", 64), ("gfx938", 128), ("gfx936", 64)):
        monkeypatch.setattr(mha.arch_info, "get_device", lambda: device)
        assert mha._get_config(False, torch.float16)["BLOCK_M"] == block_m


def test_malformed_mha_config_is_not_silently_ignored(config_dir, monkeypatch):
    monkeypatch.setattr(mha.arch_info, "get_device", lambda: "invalid")
    (config_dir / "invalid-MHA-DEFAULT.json").write_text("invalid JSON")
    with pytest.raises(json.JSONDecodeError):
        mha._get_config(False, torch.float16)


def _reference(q, k, v, lengths, causal):
    result = []
    offset = 0
    for length in lengths:
        qi, ki, vi = (
            x[offset : offset + length].float().transpose(0, 1) for x in (q, k, v)
        )
        repeats = qi.shape[0] // ki.shape[0]
        ki, vi = (x.repeat_interleave(repeats, dim=0) for x in (ki, vi))
        scores = qi @ ki.transpose(-2, -1) * q.shape[-1] ** -0.5
        if causal:
            mask = torch.ones(
                (length, length), device=q.device, dtype=torch.bool
            ).tril()
            scores = scores.masked_fill(~mask, float("-inf"))
        result.append((scores.softmax(-1) @ vi).transpose(0, 1))
        offset += length
    return torch.cat(result).to(q.dtype)


@pytest.mark.skipif(not torch.cuda.is_available(), reason="requires a GPU")
@pytest.mark.parametrize("dtype", [torch.float16, torch.bfloat16])
@pytest.mark.parametrize("causal", [False, True])
@pytest.mark.parametrize(
    "lengths,num_heads,num_kv_heads,head_dim",
    [
        ((2,), 1, 1, 64),
        ((3, 5), 4, 4, 64),
        ((5, 7), 4, 4, 80),
        ((33, 127, 257), 8, 2, 128),
    ],
)
def test_public_varlen_mha_eager_and_graph(
    config_dir, dtype, causal, lengths, num_heads, num_kv_heads, head_dim
):
    torch.manual_seed(42)
    total = sum(lengths)
    if num_heads == num_kv_heads:
        # Match the non-contiguous Q/K/V views produced by a packed projection.
        q, k, v = torch.randn(
            total, 3, num_heads, head_dim, device="cuda", dtype=dtype
        ).unbind(1)
    else:
        q = torch.randn(total, num_heads, head_dim, device="cuda", dtype=dtype)
        k = torch.randn(total, num_kv_heads, head_dim, device="cuda", dtype=dtype)
        v = torch.randn_like(k)
    cumulative = [0]
    for length in lengths:
        cumulative.append(cumulative[-1] + length)
    cu_seqlens = torch.tensor(cumulative, device="cuda", dtype=torch.int32)

    def run():
        return flash_attn_varlen_func(
            q=q,
            k=k,
            v=v,
            cu_seqlens_q=cu_seqlens,
            cu_seqlens_k=cu_seqlens,
            max_seqlen_q=max(lengths),
            max_seqlen_k=max(lengths),
            softmax_scale=None,
            causal=causal,
        )

    with torch.inference_mode():
        reference = _reference(q, k, v, lengths, causal)
        eager = run()
        torch.testing.assert_close(eager, reference, atol=1e-2, rtol=1e-2)
        warmup = torch.cuda.Stream()
        warmup.wait_stream(torch.cuda.current_stream())
        with torch.cuda.stream(warmup):
            for _ in range(3):
                run()
        torch.cuda.current_stream().wait_stream(warmup)
        torch.cuda.synchronize()
        graph = torch.cuda.CUDAGraph()
        with torch.cuda.graph(graph):
            captured = run()
        graph.replay()
        torch.testing.assert_close(captured, eager, atol=1e-3, rtol=1e-3)
        # Replay must consume fresh Q/K/V and sequence metadata, not values
        # captured on the host. Keep total tokens and the static maximum fixed.
        for x in (q, k, v):
            x.copy_(torch.randn_like(x))
        replay_lengths = list(lengths)
        if len(lengths) > 1:
            shift = (lengths[-1] - lengths[0]) // 2
            replay_lengths[0] += shift
            replay_lengths[-1] -= shift
            cumulative = [0]
            for length in replay_lengths:
                cumulative.append(cumulative[-1] + length)
            cu_seqlens.copy_(
                torch.tensor(cumulative, device="cuda", dtype=torch.int32)
            )
        graph.replay()
        reference = _reference(q, k, v, replay_lengths, causal)
        torch.testing.assert_close(captured, reference, atol=1e-2, rtol=1e-2)
