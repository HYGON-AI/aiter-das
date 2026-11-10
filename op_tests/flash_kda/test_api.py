# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
"""FlashKDA 公共契约：入口签名、原位写出、错误类型、state dtype 与后端选择。

这里只放**用户可见契约**：不测私有分派函数，也不重复 `test_fwd.py` 的数值门。
需要设备的用例使用 `gpu` fixture；纯静态/CPU 用例不取设备。

对应用例迁移来源：
``integration/test_flash_kda_hcu_api.py``、``test_state_dtype_contract.py``、
``k1/test_peer_k1_k2_varlen.py``（公共入口子集）。
"""

import inspect

import pytest
import torch

from op_tests.flash_kda import cases

#: 本文件是「普通契约」集合（入口签名/错误/dtype/后端选择）
pytestmark = pytest.mark.contract


def _run_fwd(x, *, out=None, final=None, want_final=True, workspace=None,
             cu_seqlens="auto"):
    """调用用户主入口，返回 ``(out, final, 返回值)``。"""
    from aiter.ops.flash_kda import fwd

    out = torch.empty_like(x["v"]) if out is None else out
    if final is None:
        final = torch.empty_like(x["state"]) if want_final else None
    cu = x["cu_seqlens"] if cu_seqlens == "auto" else cu_seqlens
    result = fwd(
        x["q"], x["k"], x["v"], x["g"], x["beta"], cases.SCALE, out,
        x["A_log"], x["dt_bias"], cases.LOWER_BOUND,
        initial_state=x["state"], final_state=final,
        cu_seqlens=cu, workspace=workspace,
    )
    return out, final, result


# ---------------------------------------------------------------------------
# A5：真实包导入与导出（不伪造 sys.modules 包树）
# ---------------------------------------------------------------------------
@pytest.mark.gpu
def test_user_entry_imports_from_installed_package(gpu):
    from aiter.ops.flash_kda import fwd, get_workspace_size

    assert callable(fwd)
    assert callable(get_workspace_size)
    module = inspect.getmodule(fwd)
    assert module is not None and module.__name__ == "aiter.ops.flash_kda"


@pytest.mark.gpu
def test_user_entry_signature_is_fixed(gpu):
    from aiter.ops.flash_kda import fwd, get_workspace_size

    params = list(inspect.signature(fwd).parameters.values())
    names = [p.name for p in params]
    assert names[:10] == [
        "q", "k", "v", "g", "beta", "scale", "out", "A_log", "dt_bias", "lower_bound",
    ]
    assert names[10:13] == ["initial_state", "final_state", "cu_seqlens"]
    assert names[13:] == ["workspace", "state_v_first"]
    assert all(p.kind is inspect.Parameter.KEYWORD_ONLY for p in params[13:])
    assert params[-1].default is False

    size_params = inspect.signature(get_workspace_size).parameters
    assert size_params["sequence_count"].kind is inspect.Parameter.KEYWORD_ONLY
    assert size_params["is_varlen"].kind is inspect.Parameter.KEYWORD_ONLY


@pytest.mark.gpu
def test_compat_entry_signature_is_fla_compatible(gpu):
    from aiter.ops.triton.kimi_delta_attn import chunk_kimi_delta_attn

    params = inspect.signature(chunk_kimi_delta_attn).parameters
    assert "backend" not in params
    assert "chunks_per_seg" not in params
    assert list(params)[:5] == ["q", "k", "v", "g", "beta"]
    assert list(params)[-1] == "state_dtype"
    assert params["state_dtype"].kind is inspect.Parameter.KEYWORD_ONLY


@pytest.mark.gpu
def test_get_workspace_size_is_positive_and_grows(gpu):
    from aiter.ops.flash_kda import get_workspace_size

    small = get_workspace_size(1, 1024, 6)
    large = get_workspace_size(1, 8192, 6)
    assert isinstance(small, int) and small > 0
    assert large > small


@pytest.mark.gpu
def test_get_workspace_size_varlen_requires_sequence_count(gpu):
    from aiter.ops.flash_kda import get_workspace_size

    with pytest.raises(ValueError, match="sequence_count"):
        get_workspace_size(1, 1024, 6, is_varlen=True)
    assert get_workspace_size(1, 1024, 6, sequence_count=4, is_varlen=True) > 0


# ---------------------------------------------------------------------------
# A4/A6：非法 backend 值必须在分派前报错（真实公开入口，不是私有分派）
# ---------------------------------------------------------------------------
@pytest.mark.gpu
def test_unknown_backend_is_rejected(gpu, monkeypatch):
    from aiter.ops.triton.kimi_delta_attn import chunk_kimi_delta_attn

    q = torch.zeros((1, 32, 2, 128), dtype=torch.bfloat16)
    beta = torch.zeros((1, 32, 2), dtype=torch.float32)
    monkeypatch.setenv("FLASH_KDA_BACKEND", "hcux")
    with pytest.raises(ValueError, match="unknown.*backend"):
        chunk_kimi_delta_attn(q, q.clone(), q.clone(), q.clone(), beta)


# ---------------------------------------------------------------------------
# A6/A7：主入口原位写出与错误契约
# ---------------------------------------------------------------------------
@pytest.mark.gpu
def test_fwd_writes_caller_buffers(inputs, gpu):
    out, final, result = _run_fwd(inputs)
    assert result is None
    assert torch.isfinite(out).all()
    assert torch.isfinite(final).all()


@pytest.mark.gpu
def test_fwd_without_final_buffer_only_writes_out(inputs, gpu):
    out, final, result = _run_fwd(inputs, want_final=False)
    assert result is None
    assert final is None
    assert torch.isfinite(out).all()
    # 产物与"带终态"那次在 out 上完全一致：终态不影响 out
    out_with_final, _, _ = _run_fwd(inputs)
    assert torch.equal(out, out_with_final)


@pytest.mark.gpu
@pytest.mark.parametrize("state_dtype", [torch.float32, torch.bfloat16])
def test_state_dtype_contract(gpu, state_dtype):
    x = cases.make_inputs((1, 33, 6), seed=20261029, state_dtype=state_dtype)
    out, final, _ = _run_fwd(x)
    assert out.dtype is torch.bfloat16
    assert final.dtype is state_dtype
    assert torch.isfinite(out).all() and torch.isfinite(final).all()


@pytest.mark.gpu
def test_state_dtype_conflict_is_rejected(gpu):
    from aiter.ops.flash_kda import fwd

    x = cases.make_inputs((1, 33, 6), seed=20261030, state_dtype=torch.float32)
    out = torch.empty_like(x["v"])
    mismatched = torch.empty_like(x["state"], dtype=torch.bfloat16)
    with pytest.raises(ValueError, match="state_dtype|dtype"):
        fwd(x["q"], x["k"], x["v"], x["g"], x["beta"], cases.SCALE, out,
            x["A_log"], x["dt_bias"], cases.LOWER_BOUND,
            initial_state=x["state"], final_state=mismatched)


@pytest.mark.gpu
def test_fp16_beta_is_rejected_not_converted(gpu):
    x = cases.make_inputs((1, 33, 6), seed=20261031, state_dtype=torch.float32)
    x["beta"] = x["beta"].to(torch.float16)
    with pytest.raises(NotImplementedError):
        _run_fwd(x)


@pytest.mark.gpu
def test_out_none_is_rejected_before_dispatch(gpu):
    from aiter.ops.flash_kda import fwd

    x = cases.make_inputs((1, 16, 6), seed=20261032, state_dtype=torch.float32)
    with pytest.raises(TypeError, match="out"):
        fwd(x["q"], x["k"], x["v"], x["g"], x["beta"], cases.SCALE, None,
            x["A_log"], x["dt_bias"], cases.LOWER_BOUND)


@pytest.mark.gpu
def test_preallocated_buffers_are_written_in_place(gpu):
    """预分配 out/final/workspace 与自动分配路径逐位一致（同一 native 调用）。"""
    from aiter.ops.flash_kda import get_workspace_size

    x = cases.make_inputs((1, 1024, 6), seed=20261033, state_dtype=torch.float32)
    auto_out, auto_final, _ = _run_fwd(x)

    size = get_workspace_size(1, 1024, 6)
    assert size == get_workspace_size(1, 1024, 6, sequence_count=1)
    workspace = torch.empty(size, dtype=torch.uint8, device=x["q"].device)
    pre_out = torch.empty_like(x["v"])
    pre_final = torch.empty_like(x["state"])
    assert _run_fwd(x, out=pre_out, final=pre_final, workspace=workspace)[2] is None

    assert torch.equal(auto_out, pre_out)
    assert torch.equal(auto_final, pre_final)


@pytest.mark.gpu
def test_workspace_too_small_is_rejected(gpu):
    x = cases.make_inputs((1, 1024, 6), seed=20261034, state_dtype=torch.float32)
    tiny = torch.empty(64, dtype=torch.uint8, device=x["q"].device)
    with pytest.raises(ValueError, match="workspace"):
        _run_fwd(x, workspace=tiny)


@pytest.mark.gpu
def test_workspace_base_must_be_aligned(gpu):
    from aiter.ops.flash_kda import get_workspace_size

    x = cases.make_inputs((1, 1024, 6), seed=20261035, state_dtype=torch.float32)
    size = get_workspace_size(1, 1024, 6)
    buffer = torch.empty(size + 1, dtype=torch.uint8, device=x["q"].device)
    with pytest.raises(ValueError, match="align|workspace"):
        _run_fwd(x, workspace=buffer[1:])


@pytest.mark.gpu
def test_output_overlapping_input_is_rejected(gpu):
    x = cases.make_inputs((1, 1024, 6), seed=20261036, state_dtype=torch.float32)
    with pytest.raises(ValueError, match="overlap"):
        _run_fwd(x, out=x["v"])


@pytest.mark.gpu
def test_empty_sequence_keeps_initial_state(gpu):
    """全空序列：out 为空，终态逐位等于初态。"""
    x = cases.make_inputs((1, 0, 6), seed=20261037, state_dtype=torch.float32,
                          lengths=[0, 0, 0])
    out, final, result = _run_fwd(x)
    assert result is None
    assert tuple(out.shape) == (1, 0, 6, 128)
    assert torch.equal(final, x["state"])


@pytest.mark.gpu
def test_int32_cu_matches_int64(gpu):
    """INT32 cu 是既有扩展：与 INT64 结果逐位一致。"""
    x = cases.make_inputs((1, 33, 6), seed=20261038, state_dtype=torch.float32,
                          lengths=[17, 16])
    out64, final64, _ = _run_fwd(x)
    out32, final32, _ = _run_fwd(x, cu_seqlens=x["cu_seqlens"].to(torch.int32))
    assert torch.equal(out64, out32)
    assert torch.equal(final64, final32)


# ---------------------------------------------------------------------------
# A8/B6：兼容入口（chunk_kimi_delta_attn）与主入口的封装等价
# ---------------------------------------------------------------------------
def _compat(x, backend, monkeypatch, *, enable=None):
    from aiter.ops.triton.kimi_delta_attn import chunk_kimi_delta_attn

    monkeypatch.setenv("FLASH_KDA_BACKEND", backend)
    if enable is not None:
        monkeypatch.setenv("FLASH_KDA_HCU_ENABLE", enable)
    return chunk_kimi_delta_attn(
        x["q"], x["k"], x["v"], x["g"], x["beta"],
        A_log=x["A_log"], dt_bias=x["dt_bias"], scale=cases.SCALE,
        initial_state=x["state"], output_final_state=True,
        use_qk_l2norm_in_kernel=True, use_gate_in_kernel=True,
        use_beta_sigmoid_in_kernel=True, safe_gate=True,
        lower_bound=cases.LOWER_BOUND, cu_seqlens=x["cu_seqlens"],
        state_dtype=x["state"].dtype,
    )


@pytest.mark.gpu
def test_compat_hcu_entry_is_equivalent_to_fwd(gpu, monkeypatch):
    """封装等价（不是独立算法验证）：HCU 成功路径与主入口逐位相同。"""
    x = cases.make_inputs((1, 1024, 6), seed=20261039, state_dtype=torch.float32)
    fwd_out, fwd_final, _ = _run_fwd(x)
    compat_out, compat_final = _compat(x, "hcu", monkeypatch)
    assert torch.equal(fwd_out, compat_out)
    assert torch.equal(fwd_final, compat_final)


@pytest.mark.gpu
def test_compat_triton_backend_returns_tuple(gpu, monkeypatch):
    x = cases.make_inputs((1, 64, 6), seed=20261040, state_dtype=torch.float32)
    out, final = _compat(x, "triton", monkeypatch)
    assert tuple(out.shape) == tuple(x["v"].shape)
    assert out.dtype is torch.bfloat16
    assert final is not None and tuple(final.shape) == tuple(x["state"].shape)
    assert torch.isfinite(out).all() and torch.isfinite(final).all()


@pytest.mark.gpu
def test_compat_auto_falls_back_when_hcu_unsupported(gpu, monkeypatch):
    """BF16 beta 属"合法但 HCU 不支持"，auto 必须回退 Triton 并正常出数。"""
    x = cases.make_inputs((1, 64, 6), seed=20261041, state_dtype=torch.float32)
    x["beta"] = x["beta"].to(torch.bfloat16)
    out, _ = _compat(x, "auto", monkeypatch, enable="1")
    assert tuple(out.shape) == tuple(x["v"].shape)
    assert torch.isfinite(out.float()).all()


@pytest.mark.gpu
def test_compat_rejects_shape_and_varlen_contract_errors(gpu):
    from aiter.ops.triton.kimi_delta_attn import chunk_kimi_delta_attn

    x = cases.make_inputs((1, 32, 2), seed=20261042, state_dtype=torch.float32)
    with pytest.raises(ValueError, match="same shape"):
        chunk_kimi_delta_attn(x["q"], x["k"][:, :16], x["v"], x["g"], x["beta"])
    with pytest.raises(ValueError, match="shape"):
        chunk_kimi_delta_attn(x["q"], x["k"], x["v"], x["g"][:, :, :, :64], x["beta"])
    b2 = cases.make_inputs((2, 32, 2), seed=20261043, state_dtype=torch.float32)
    with pytest.raises(ValueError, match="varlen"):
        chunk_kimi_delta_attn(b2["q"], b2["k"], b2["v"], b2["g"], b2["beta"],
                              cu_seqlens=torch.tensor([0, 32]))


@pytest.mark.gpu
def test_compat_rejects_gate_scale_and_bounds(gpu):
    from aiter.ops.triton.kimi_delta_attn import chunk_kimi_delta_attn

    x = cases.make_inputs((1, 32, 2), seed=20261044, state_dtype=torch.float32)
    with pytest.raises(ValueError, match="A_log"):
        chunk_kimi_delta_attn(x["q"], x["k"], x["v"], x["g"], x["beta"],
                              use_gate_in_kernel=True)
    with pytest.raises(ValueError, match="lower_bound"):
        chunk_kimi_delta_attn(x["q"], x["k"], x["v"], x["g"], x["beta"],
                              A_log=x["A_log"], use_gate_in_kernel=True,
                              safe_gate=True, lower_bound=None)
    with pytest.raises(ValueError, match="scale"):
        chunk_kimi_delta_attn(x["q"], x["k"], x["v"], x["g"], x["beta"], scale=0)


# ---------------------------------------------------------------------------
# CPU-only：metric 语义（非有限值一律判失败）
# ---------------------------------------------------------------------------
def test_measure_error_rejects_non_finite():
    from op_tests.flash_kda import reference

    bad = reference.measure_error(torch.tensor([float("nan"), 1.0]), torch.ones(2))
    assert bad["pass"] is False and bad["finite"] is False
    same = reference.measure_error(torch.ones(3), torch.ones(3))
    assert same["pass"] is True and same["max_abs"] == 0.0 and same["nbad"] == 0
    empty = reference.measure_error(torch.zeros(0), torch.zeros(0))
    assert empty["pass"] is True and empty["numel"] == 0


# ---------------------------------------------------------------------------
# CPU-only：state dtype 解析规则（不触发 native 模块）
# ---------------------------------------------------------------------------
@pytest.mark.parametrize("dtype", [torch.float32, torch.bfloat16])
def test_state_dtype_infer_and_explicit(dtype):
    from aiter.ops.flash_kda_state import resolve_state_dtype

    state = torch.empty((1, 1, 128, 128), dtype=dtype)
    assert resolve_state_dtype(state, None) == dtype
    assert resolve_state_dtype(state, dtype) == dtype
    assert resolve_state_dtype(None, dtype) == dtype


def test_state_dtype_default_and_invalid():
    from aiter.ops.flash_kda_state import resolve_state_dtype

    assert resolve_state_dtype(None, None) == torch.float32
    with pytest.raises(TypeError):
        resolve_state_dtype(None, torch.float16)
    with pytest.raises(TypeError):
        resolve_state_dtype(torch.empty(1, dtype=torch.int32), None)
    with pytest.raises(TypeError):
        resolve_state_dtype(None, torch.int32)


@pytest.mark.parametrize("a,b", [(torch.float32, torch.bfloat16),
                                 (torch.bfloat16, torch.float32)])
def test_state_dtype_mismatch_raises(a, b):
    from aiter.ops.flash_kda_state import resolve_state_dtype

    with pytest.raises(ValueError):
        resolve_state_dtype(torch.empty(1, dtype=a), b)
