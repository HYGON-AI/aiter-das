# SPDX-License-Identifier: MIT

import os

import torch

from ...flash_kda_state import resolve_state_dtype


def _hcu_auto_enabled() -> bool:
    return os.getenv("FLASH_KDA_HCU_ENABLE", "0").lower() in {
        "1",
        "true",
        "yes",
        "on",
    }


def _triton_forward(q, k, v, g, beta, **kwargs):
    from .chunk_fwd import chunk_delta_attn_fwd

    K = q.shape[-1]
    scale = kwargs.get("scale")
    if scale is None:
        scale = K**-0.5
    # BF16 外部 state 只是 Triton 后端为省转换而支持的便利：
    # 这里递推仍保持 FP32，终态在返回时转换。
    state_dtype = kwargs.get("state_dtype") or torch.float32
    initial_state = kwargs.get("initial_state")
    if initial_state is not None and initial_state.dtype is torch.bfloat16:
        initial_state = initial_state.float()
    result = chunk_delta_attn_fwd(
        q=q,
        k=k,
        v=v,
        g=g,
        beta=beta,
        A_log=kwargs.get("A_log"),
        dt_bias=kwargs.get("dt_bias"),
        scale=scale,
        lower_bound=kwargs.get("lower_bound", -5.0),
        initial_state=initial_state,
        output_final_state=kwargs.get("output_final_state", False),
        state_v_first=kwargs.get("state_v_first", False),
        cu_seqlens=kwargs.get("cu_seqlens"),
        chunk_size=kwargs.get("chunk_size"),
        safe_gate=kwargs.get("safe_gate", False),
        use_gate_in_kernel=kwargs.get("use_gate_in_kernel", False),
        use_qk_l2norm_in_kernel=kwargs.get("use_qk_l2norm_in_kernel", False),
        use_beta_sigmoid_in_kernel=kwargs.get("use_beta_sigmoid_in_kernel", False),
        disable_recompute=False,
    )
    final_state = result[1]
    if final_state is not None and final_state.dtype is not state_dtype:
        final_state = final_state.to(state_dtype)
    return result[0].to(q.dtype), final_state


def _hcu_single_forward(q, k, v, g, beta, **kwargs):
    """HCU 成功路径的唯一 native 调用：一次 FFI 完成校验、分配与全部 launch。

    `allow_fallback=True` 表示"合法但不支持"时返回 None（供 auto 回退判断）；
    真正的输入非法仍由 native 抛 ValueError。
    """
    from ...opus.flash_kda_forward import _features_from_flags, _forward as _fwd

    features = _features_from_flags(
        kwargs.get("use_qk_l2norm_in_kernel", False),
        kwargs.get("use_gate_in_kernel", False),
        kwargs.get("use_beta_sigmoid_in_kernel", False),
        kwargs.get("safe_gate", False),
        kwargs.get("state_v_first", False),
        kwargs.get("disable_recompute", False),
    )
    result = _fwd(
        q, k, v, g, beta,
        kwargs.get("A_log"),
        kwargs.get("dt_bias"),
        scale=kwargs.get("scale"),
        lower_bound=kwargs.get("lower_bound"),
        initial_state=kwargs.get("initial_state"),
        output_final_state=kwargs.get("output_final_state", False),
        state_dtype=kwargs.get("state_dtype"),
        cu_seqlens=kwargs.get("cu_seqlens"),
        features=features,
        chunk_size=kwargs.get("chunk_size"),
        allow_fallback=True,
        normalize_inputs=True,
    )
    return result


def _validate_public(q, k, v, g, beta, A_log, scale, lower_bound, use_gate_in_kernel,
                     safe_gate, cu_seqlens):
    """公开契约校验（HCU 与 Triton 共用同一套报错）。返回 (B, T, H, scale)。"""
    if q.ndim != 4 or k.ndim != 4 or v.ndim != 4 or g.ndim != 4 or beta.ndim != 3:
        raise ValueError("q/k/v/g must be 4D tensors and beta must be 3D")
    B, T, H, K = q.shape
    HV = v.shape[2]
    if B <= 0 or H <= 0:
        raise ValueError("B and H must be positive")
    if q.shape != k.shape:
        raise ValueError(f"q and k must have the same shape, got {q.shape} vs {k.shape}")
    if K > 256:
        raise ValueError(f"Only key head dim <= 256 is supported, got {K}")
    if HV <= 0 or HV % H != 0:
        raise ValueError(f"num_v_heads (HV={HV}) must be a positive multiple of H={H}")
    if tuple(g.shape) != (B, T, HV, K):
        raise ValueError(f"g must have shape {(B, T, HV, K)}, got {tuple(g.shape)}")
    if tuple(beta.shape) != (B, T, HV):
        raise ValueError(f"beta must have shape {(B, T, HV)}, got {tuple(beta.shape)}")
    if cu_seqlens is not None and B != 1:
        raise ValueError("varlen mode requires B=1")
    if T <= 0 and cu_seqlens is None:
        raise ValueError("T must be positive")
    if use_gate_in_kernel and A_log is None:
        raise ValueError("A_log must be provided when use_gate_in_kernel=True")
    if safe_gate and use_gate_in_kernel:
        if lower_bound is None or not -5 <= lower_bound < 0:
            raise ValueError("lower_bound must be in safe range [-5, 0)")
    if scale is None:
        scale = q.shape[-1] ** -0.5
    elif scale <= 0:
        raise ValueError("scale must be positive")
    return scale


def _compat_entry(
    q, k, v, g, beta, A_log, dt_bias, scale, initial_state, output_final_state,
    use_qk_l2norm_in_kernel, use_gate_in_kernel, use_beta_sigmoid_in_kernel,
    safe_gate, lower_bound, state_v_first, disable_recompute, chunk_size, cu_seqlens,
    state_dtype,
):
    """Triton 路径的兼容处理：契约校验 + 必要连续化 + 调用。"""
    scale = _validate_public(q, k, v, g, beta, A_log, scale, lower_bound,
                             use_gate_in_kernel, safe_gate, cu_seqlens)
    state_dtype = resolve_state_dtype(initial_state, state_dtype)
    q, k, v, g, beta = (x.contiguous() for x in (q, k, v, g, beta))
    if A_log is not None:
        A_log = A_log.contiguous()
    if dt_bias is not None:
        dt_bias = dt_bias.contiguous()
    if initial_state is not None:
        initial_state = initial_state.contiguous()
    if cu_seqlens is not None:
        cu_seqlens = cu_seqlens.contiguous()
    return _triton_forward(
        q, k, v, g, beta,
        A_log=A_log, dt_bias=dt_bias, scale=scale, initial_state=initial_state,
        output_final_state=output_final_state,
        use_qk_l2norm_in_kernel=use_qk_l2norm_in_kernel,
        use_gate_in_kernel=use_gate_in_kernel,
        use_beta_sigmoid_in_kernel=use_beta_sigmoid_in_kernel,
        safe_gate=safe_gate, lower_bound=lower_bound, state_v_first=state_v_first,
        disable_recompute=disable_recompute, chunk_size=chunk_size,
        cu_seqlens=cu_seqlens, state_dtype=state_dtype,
    )


def chunk_kimi_delta_attn(
    q: torch.Tensor,
    k: torch.Tensor,
    v: torch.Tensor,
    g: torch.Tensor,
    beta: torch.Tensor,
    A_log: torch.Tensor | None = None,
    dt_bias: torch.Tensor | None = None,
    scale: float | None = None,
    initial_state: torch.Tensor | None = None,
    output_final_state: bool = False,
    use_qk_l2norm_in_kernel: bool = False,
    use_gate_in_kernel: bool = False,
    use_beta_sigmoid_in_kernel: bool = False,
    safe_gate: bool = False,
    lower_bound: float | None = None,
    state_v_first: bool = False,
    disable_recompute: bool = False,
    chunk_size: int | None = None,
    cu_seqlens: torch.Tensor | None = None,
    *,
    state_dtype: torch.dtype | None = None,
) -> tuple[torch.Tensor, torch.Tensor | None]:
    """与 AMD AITER 兼容的 FlashKDA forward 入口。

    HCU 成功路径只调用一次 native forward（校验、连续化、workspace 分配与全部
    kernel launch 都在 native 内完成）；Triton 与 auto 回退仍走原兼容处理。

    `FLASH_KDA_BACKEND` 只接受 `auto`/`triton`/`hcu`，其它取值在分派前报 `ValueError`。
    """
    backend = os.getenv("FLASH_KDA_BACKEND", "auto").lower()
    # 非法后端值必须在分派前报错：否则会被静默当成 Triton 兼容路径执行。
    if backend not in {"auto", "triton", "hcu"}:
        raise ValueError(f"unknown Flash KDA backend: {backend!r}")
    if backend == "hcu" or (backend == "auto" and _hcu_auto_enabled()):
        result = _hcu_single_forward(
            q, k, v, g, beta,
            A_log=A_log, dt_bias=dt_bias, scale=scale,
            initial_state=initial_state, output_final_state=output_final_state,
            use_qk_l2norm_in_kernel=use_qk_l2norm_in_kernel,
            use_gate_in_kernel=use_gate_in_kernel,
            use_beta_sigmoid_in_kernel=use_beta_sigmoid_in_kernel,
            safe_gate=safe_gate, lower_bound=lower_bound,
            state_v_first=state_v_first, disable_recompute=disable_recompute,
            chunk_size=chunk_size, cu_seqlens=cu_seqlens, state_dtype=state_dtype,
        )
        if result is not None and result[0] is not None:
            return result
        if backend == "hcu":
            # 非法输入要用公开契约的错误类型暴露，而不是笼统的"不支持"。
            _validate_public(q, k, v, g, beta, A_log, scale, lower_bound,
                             use_gate_in_kernel, safe_gate, cu_seqlens)
            raise NotImplementedError("HCU Flash KDA is unsupported")
    return _compat_entry(
        q, k, v, g, beta, A_log, dt_bias, scale, initial_state, output_final_state,
        use_qk_l2norm_in_kernel, use_gate_in_kernel, use_beta_sigmoid_in_kernel,
        safe_gate, lower_bound, state_v_first, disable_recompute, chunk_size,
        cu_seqlens, state_dtype,
    )
