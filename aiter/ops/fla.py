# SPDX-License-Identifier: MIT
"""
ROCm/HIP wrappers for the Fast Linear Attention (FLA) family.

The public wrappers mirror the Triton vLLM/SGLang Python APIs as closely as the
current HIP implementation allows. The pybind layer still returns tensor-only
lists, so this module normalizes optional outputs such as ``v_new=None``.

Varlen ``chunk_indices`` / ``chunk_offsets`` are filled on the Python side when
missing; caller tensors are not moved. Runtime dtype rules:

- ``cu_seqlens``: int32 or int64; HIP dispatches ``IndexT`` from it.
- ``chunk_indices``: int32 or int64; need not match ``cu_seqlens``
  (host-side NT = ``size(0)`` only; kernel does not read elements).
- ``chunk_offsets``: always int64 (integer ``cumsum`` promotion).
"""

import torch
from typing import Any, List, Optional, Tuple

from ..jit.core import compile_ops


def _ensure_varlen_meta(
    cu_seqlens: Optional[torch.Tensor],
    chunk_size: int,
    chunk_indices: Optional[torch.Tensor],
    chunk_offsets: Optional[torch.Tensor],
    need_chunk_offsets: bool = True,
) -> Tuple[Optional[torch.Tensor], Optional[torch.Tensor], Optional[torch.Tensor]]:
    """
    Fill missing varlen meta; do not move or cast caller tensors.

    Returns (cu_seqlens, chunk_indices, chunk_offsets), or (None, None, None)
    when not varlen. Same trust model as SGLang: caller owns device/dtype.
    """
    if cu_seqlens is None:
        return None, None, None

    def _prepare_chunk_offsets(cu: torch.Tensor, bt: int) -> torch.Tensor:
        # Exclusive per-sequence chunk starts; shape (N,), always int64.
        # Match SGLang: integer cumsum promotes to int64 regardless of cu dtype.
        seq_lens = cu[1:] - cu[:-1]
        chunk_counts = (seq_lens + bt - 1) // bt
        offsets = torch.zeros(chunk_counts.shape, dtype=torch.long, device=cu.device)
        if offsets.numel() > 1:
            offsets[1:] = torch.cumsum(chunk_counts, dim=0)[:-1]
        return offsets

    def _prepare_chunk_indices(cu: torch.Tensor, bt: int) -> torch.Tensor:
        # (NT, 2) rows of [seq_id, local_chunk_idx]; dtype matches cu by default.
        device = cu.device
        n = int(cu.shape[0]) - 1
        if n <= 0:
            return torch.empty((0, 2), dtype=cu.dtype, device=device)

        seq_lens = (cu[1:] - cu[:-1]).to(torch.long)
        chunk_counts = (seq_lens + bt - 1) // bt
        seq_ids = torch.repeat_interleave(
            torch.arange(n, device=device, dtype=torch.long), chunk_counts
        )
        nt = seq_ids.numel()
        if nt == 0:
            return torch.empty((0, 2), dtype=cu.dtype, device=device)

        starts = torch.zeros(n, device=device, dtype=torch.long)
        if n > 1:
            starts[1:] = torch.cumsum(chunk_counts, dim=0)[:-1]
        local = torch.arange(nt, device=device, dtype=torch.long) - torch.repeat_interleave(
            starts, chunk_counts
        )
        return torch.stack((seq_ids, local), dim=1).to(cu)

    if chunk_indices is None or chunk_indices.numel() == 0:
        chunk_indices = _prepare_chunk_indices(cu_seqlens, chunk_size)

    if need_chunk_offsets and (chunk_offsets is None or chunk_offsets.numel() == 0):
        chunk_offsets = _prepare_chunk_offsets(cu_seqlens, chunk_size)

    return cu_seqlens, chunk_indices, chunk_offsets


@compile_ops("module_cpp_api", fc_name="chunk_gated_delta_rule_fwd_vllm_hip_blockdim64")
def _chunk_gated_delta_rule_fwd_vllm_hip_blockdim64(
    k: torch.Tensor,
    w: torch.Tensor,
    u: torch.Tensor,
    g: Optional[torch.Tensor],
    gk: Optional[torch.Tensor],
    initial_state: Optional[torch.Tensor],
    initial_state_indices: Optional[torch.Tensor],
    output_final_state: bool,
    chunk_size: int,
    save_new_value: bool,
    cu_seqlens: Optional[torch.Tensor],
    chunk_indices: Optional[torch.Tensor],
    chunk_offsets: Optional[torch.Tensor],
    use_exp2: bool,
    transpose_state_layout: bool,
) -> List[torch.Tensor]:
    ...


@compile_ops("module_cpp_api", fc_name="chunk_gated_delta_rule_fwd_sglang_hip_blockdim64")
def _chunk_gated_delta_rule_fwd_sglang_hip_blockdim64(
    k: torch.Tensor,
    w: torch.Tensor,
    u: torch.Tensor,
    g: Optional[torch.Tensor],
    gk: Optional[torch.Tensor],
    initial_state: Optional[torch.Tensor],
    initial_state_indices: Optional[torch.Tensor],
    output_final_state: bool,
    chunk_size: int,
    save_new_value: bool,
    cu_seqlens: Optional[torch.Tensor],
    chunk_indices: Optional[torch.Tensor],
    chunk_offsets: Optional[torch.Tensor],
    use_exp2: bool,
    transpose_state_layout: bool,
) -> List[torch.Tensor]:
    ...

@compile_ops("module_cpp_api", fc_name="vllm_fused_sigmoid_gating_delta_rule_update")
def _vllm_fused_sigmoid_gating_delta_rule_update(
    A_log: torch.Tensor,
    a: torch.Tensor,
    b: torch.Tensor,
    dt_bias: torch.Tensor,
    q: torch.Tensor,
    k: torch.Tensor,
    v: torch.Tensor,
    beta: float = 1.0,
    threshold: float = 20.0,
    scale: Optional[float] = None,
    initial_state: Optional[torch.Tensor] = None,
    inplace_final_state: bool = True,
    cu_seqlens: Optional[torch.Tensor] = None,
    ssm_state_indices: Optional[torch.Tensor] = None,
    num_accepted_tokens: Optional[torch.Tensor] = None,
    use_qk_l2norm_in_kernel: bool = False,
    is_kda: bool = False,
) -> List[torch.Tensor]:
    ...

@compile_ops("module_cpp_api", fc_name="aiter_fused_recurrent_gated_delta_rule_packed_decode")
def _aiter_fused_recurrent_gated_delta_rule_packed_decode(
    mixed_qkv: torch.Tensor,
    a: torch.Tensor,
    b: torch.Tensor,
    A_log: torch.Tensor,
    dt_bias: torch.Tensor,
    scale: float,
    initial_state: torch.Tensor,
    out: torch.Tensor,
    ssm_state_indices: torch.Tensor,
    use_qk_l2norm_in_kernel: bool = False,
) -> List[torch.Tensor]:
    ...

@compile_ops("module_cpp_api", fc_name="chunk_fwd_o_vllm_hip_blockdim64")
def _chunk_fwd_o_vllm_hip_blockdim64(
    q: torch.Tensor,
    k: torch.Tensor,
    v: torch.Tensor,
    h: torch.Tensor,
    g: Optional[torch.Tensor],
    g_gamma: Optional[torch.Tensor],
    scale: float,
    cu_seqlens: Optional[torch.Tensor],
    chunk_indices: Optional[torch.Tensor],
    chunk_size: int,
    use_exp2: bool,
    transpose_state_layout: bool,
) -> torch.Tensor:
    ...

def chunk_gated_delta_rule_fwd_vllm_hip_blockdim64(
    k: torch.Tensor,
    w: torch.Tensor,
    u: torch.Tensor,
    g: Optional[torch.Tensor] = None,
    gk: Optional[torch.Tensor] = None,
    initial_state: Optional[torch.Tensor] = None,
    initial_state_indices: Optional[torch.Tensor] = None,
    output_final_state: bool = True,
    chunk_size: int = 64,
    save_new_value: bool = True,
    cu_seqlens: Optional[torch.Tensor] = None,
    chunk_indices: Optional[torch.Tensor] = None,
    chunk_offsets: Optional[torch.Tensor] = None,
    use_exp2: bool = False,
    transpose_state_layout: bool = True,
    kernel_cfg: Optional[dict[str, Any]] = None,
) -> tuple[torch.Tensor, Optional[torch.Tensor], Optional[torch.Tensor]]:
    """vLLM-aligned HIP blockdim64 chunked gated delta-rule forward."""
    del kernel_cfg
    cu_seqlens, chunk_indices, chunk_offsets = _ensure_varlen_meta(
        cu_seqlens, chunk_size, chunk_indices, chunk_offsets
    )
    h, v_new, final_state = _chunk_gated_delta_rule_fwd_vllm_hip_blockdim64(
        k,
        w,
        u,
        g,
        gk,
        initial_state,
        initial_state_indices,
        output_final_state,
        chunk_size,
        save_new_value,
        cu_seqlens,
        chunk_indices,
        chunk_offsets,
        use_exp2,
        transpose_state_layout,
    )
    if not save_new_value:
        v_new = None
    if not output_final_state:
        final_state = None
    return h, v_new, final_state


def chunk_gated_delta_rule_fwd_sglang_hip_blockdim64(
    k: torch.Tensor,
    w: torch.Tensor,
    u: torch.Tensor,
    g: Optional[torch.Tensor] = None,
    gk: Optional[torch.Tensor] = None,
    initial_state: Optional[torch.Tensor] = None,
    initial_state_indices: Optional[torch.Tensor] = None,
    output_final_state: bool = True,
    chunk_size: int = 64,
    save_new_value: bool = True,
    cu_seqlens: Optional[torch.Tensor] = None,
    chunk_indices: Optional[torch.Tensor] = None,
    chunk_offsets: Optional[torch.Tensor] = None,
    use_exp2: bool = False,
    transpose_state_layout: bool = True,
    kernel_cfg: Optional[dict[str, Any]] = None,
) -> tuple[torch.Tensor, Optional[torch.Tensor]]:
    """SGLang-aligned HIP forward with an in-place FP32/BF16 state-pool update.

    ``initial_state`` may have a non-compact slot stride while its H/V/K
    dimensions remain dense. An ``initial_state_indices`` entry of ``-1``
    selects zero initial state for that sequence and suppresses pool writeback.
    Nonnegative entries must identify unique valid pool slots.

    ``output_final_state`` is retained for signature compatibility with the
    SGLang Triton API but does not control the in-place update. Every valid slot
    is written back even when this argument is ``False``.
    """
    del kernel_cfg
    cu_seqlens, chunk_indices, chunk_offsets = _ensure_varlen_meta(
        cu_seqlens, chunk_size, chunk_indices, chunk_offsets
    )
    h, v_new = _chunk_gated_delta_rule_fwd_sglang_hip_blockdim64(
        k,
        w,
        u,
        g,
        gk,
        initial_state,
        initial_state_indices,
        output_final_state,
        chunk_size,
        save_new_value,
        cu_seqlens,
        chunk_indices,
        chunk_offsets,
        use_exp2,
        transpose_state_layout,
    )
    if not save_new_value:
        v_new = None
    return h, v_new

def vllm_fused_sigmoid_gating_delta_rule_update(
    A_log: torch.Tensor,
    a: torch.Tensor,
    b: torch.Tensor,
    dt_bias: torch.Tensor,
    q: torch.Tensor,
    k: torch.Tensor,
    v: torch.Tensor,
    beta: float = 1.0,
    threshold: float = 20.0,
    scale: Optional[float] = None,
    initial_state: Optional[torch.Tensor] = None,
    inplace_final_state: bool = True,
    cu_seqlens: Optional[torch.Tensor] = None,
    ssm_state_indices: Optional[torch.Tensor] = None,
    num_accepted_tokens: Optional[torch.Tensor] = None,
    use_qk_l2norm_in_kernel: bool = False,
    is_kda: bool = False,
) -> Tuple[torch.Tensor, torch.Tensor]:
    out, final_state = _vllm_fused_sigmoid_gating_delta_rule_update(
        A_log,
        a,
        b,
        dt_bias,
        q,
        k,
        v,
        beta,
        threshold,
        scale,
        initial_state,
        inplace_final_state,
        cu_seqlens,
        ssm_state_indices,
        num_accepted_tokens,
        use_qk_l2norm_in_kernel,
        is_kda,
    )
    return out, final_state

def aiter_fused_recurrent_gated_delta_rule_packed_decode(
    mixed_qkv: torch.Tensor,
    a: torch.Tensor,
    b: torch.Tensor,
    A_log: torch.Tensor,
    dt_bias: torch.Tensor,
    scale: float,
    initial_state: torch.Tensor,
    out: torch.Tensor,
    ssm_state_indices: torch.Tensor,
    use_qk_l2norm_in_kernel: bool = False,
    kernel_cfg: Optional[dict[str, Any]] = None,
) -> Tuple[torch.Tensor, torch.Tensor]:
    del kernel_cfg
    out, final_state = _aiter_fused_recurrent_gated_delta_rule_packed_decode(
        mixed_qkv,
        a,
        b,
        A_log,
        dt_bias,
        scale,
        initial_state,
        out,
        ssm_state_indices,
        use_qk_l2norm_in_kernel,
    )
    return out, final_state

def chunk_fwd_o_vllm_hip_blockdim64(
    q: torch.Tensor,
    k: torch.Tensor,
    v: torch.Tensor,
    h: torch.Tensor,
    g: Optional[torch.Tensor] = None,
    g_gamma: Optional[torch.Tensor] = None,
    scale: Optional[float] = None,
    cu_seqlens: Optional[torch.Tensor] = None,
    chunk_size: int = 64,
    chunk_indices: Optional[torch.Tensor] = None,
    use_exp2: bool = False,
    transpose_state_layout: bool = True,
    kernel_cfg: Optional[dict[str, Any]] = None,
) -> torch.Tensor:
    """vLLM-aligned HIP blockdim64 chunk_fwd_o."""
    del kernel_cfg
    if scale is None:
        scale = k.shape[-1] ** -0.5
    # The chunk_fwd_o native ABI consumes cu_seqlens/chunk_indices only.
    cu_seqlens, chunk_indices, _ = _ensure_varlen_meta(
        cu_seqlens,
        chunk_size,
        chunk_indices,
        None,
        need_chunk_offsets=False,
    )
    return _chunk_fwd_o_vllm_hip_blockdim64(
        q,
        k,
        v,
        h,
        g,
        g_gamma,
        float(scale),
        cu_seqlens,
        chunk_indices,
        chunk_size,
        use_exp2,
        transpose_state_layout,
    )

# Backward-compatible Python aliases. New callers should use the explicit names above.
def chunk_gated_delta_rule_fwd(
    k: torch.Tensor,
    w: torch.Tensor,
    u: torch.Tensor,
    g: Optional[torch.Tensor] = None,
    gk: Optional[torch.Tensor] = None,
    initial_state: Optional[torch.Tensor] = None,
    initial_state_indices: Optional[torch.Tensor] = None,
    output_final_state: bool = True,
    chunk_size: int = 64,
    save_new_value: bool = True,
    cu_seqlens: Optional[torch.Tensor] = None,
    chunk_indices: Optional[torch.Tensor] = None,
    chunk_offsets: Optional[torch.Tensor] = None,
    use_exp2: bool = False,
    transpose_state_layout: bool = True,
    kernel_cfg: Optional[dict[str, Any]] = None,
) -> tuple[torch.Tensor, Optional[torch.Tensor], Optional[torch.Tensor]]:
    return chunk_gated_delta_rule_fwd_vllm_hip_blockdim64(
        k,
        w,
        u,
        g,
        gk,
        initial_state,
        initial_state_indices,
        output_final_state,
        chunk_size,
        save_new_value,
        cu_seqlens,
        chunk_indices,
        chunk_offsets,
        use_exp2,
        transpose_state_layout,
        kernel_cfg,
    )


def chunk_gated_delta_rule_fwd_sglang(
    k: torch.Tensor,
    w: torch.Tensor,
    u: torch.Tensor,
    g: Optional[torch.Tensor] = None,
    gk: Optional[torch.Tensor] = None,
    initial_state: Optional[torch.Tensor] = None,
    initial_state_indices: Optional[torch.Tensor] = None,
    output_final_state: bool = True,
    chunk_size: int = 64,
    save_new_value: bool = True,
    cu_seqlens: Optional[torch.Tensor] = None,
    chunk_indices: Optional[torch.Tensor] = None,
    chunk_offsets: Optional[torch.Tensor] = None,
    use_exp2: bool = False,
    transpose_state_layout: bool = True,
    kernel_cfg: Optional[dict[str, Any]] = None,
) -> tuple[torch.Tensor, Optional[torch.Tensor]]:
    return chunk_gated_delta_rule_fwd_sglang_hip_blockdim64(
        k,
        w,
        u,
        g,
        gk,
        initial_state,
        initial_state_indices,
        output_final_state,
        chunk_size,
        save_new_value,
        cu_seqlens,
        chunk_indices,
        chunk_offsets,
        use_exp2,
        transpose_state_layout,
        kernel_cfg,
    )
