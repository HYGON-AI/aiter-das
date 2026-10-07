# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
"""
Native CK GDN wrappers.

These entry points expose the CK Tile GDN implementation
(3rdparty/composable_kernel/example_hcu/ck_tile/21_gdn) directly: the CK
launchers are called as-is, so the semantics, constraints and numerics are
CK's own. The HIPC implementation lives in ``aiter.ops.fla`` (module_cpp_api)
and the Triton reference lives in ``aiter.ops.triton.fla``; there is no
implicit fallback between them.

CK GDN constraints (enforced by the native layer):

* ``head_dim == 128`` and ``chunk_size == 64`` are fixed;
* ``h_v / h_qk`` must be in ``{1, 2, 4}``;
* inputs are packed -- there is no leading batch dimension;
* prefill always materialises ``v_new`` internally because CK's output stage
  consumes it;
* the prefill workspace is caller-provided (see
  :func:`ck_gdn_prefill_workspace_bytes` / :func:`ck_gdn_prefill_alloc_workspace`).

Example
-------
>>> import torch, aiter
>>> q = torch.randn(1024, 2, 128, dtype=torch.bfloat16, device="cuda")
>>> v = torch.randn(1024, 8, 128, dtype=torch.bfloat16, device="cuda")
>>> ws = aiter.ck_gdn_prefill_alloc_workspace(q, v)
>>> out, final_state = aiter.ck_gdn_prefill(q, q, v, g, beta, ws)
"""

from typing import List, Optional, Tuple

import torch

from ..jit.core import compile_ops


@compile_ops("module_gdn_ck", fc_name="ck_gdn_prefill_workspace_bytes")
def _ck_gdn_prefill_workspace_bytes(
    q: torch.Tensor,
    v: torch.Tensor,
    cu_seqlens: Optional[torch.Tensor] = None,
    use_g: bool = True,
    use_gk: bool = False,
    use_exp2: bool = True,
    transpose_state: bool = False,
    qk_l2norm: bool = False,
    gate_in_kernel: bool = False,
    has_dt_bias: bool = False,
    beta_sigmoid_in_kernel: bool = False,
    output_final_state: bool = True,
    cp_context: bool = False,
    cp_world_size: int = 2,
) -> int:
    ...


@compile_ops("module_gdn_ck", fc_name="ck_gdn_prefill")
def _ck_gdn_prefill(
    q: torch.Tensor,
    k: torch.Tensor,
    v: torch.Tensor,
    g: Optional[torch.Tensor],
    beta: torch.Tensor,
    workspace: Optional[torch.Tensor] = None,
    gk: Optional[torch.Tensor] = None,
    a_log: Optional[torch.Tensor] = None,
    dt_bias: Optional[torch.Tensor] = None,
    initial_state: Optional[torch.Tensor] = None,
    cu_seqlens: Optional[torch.Tensor] = None,
    scale: Optional[float] = None,
    use_g: bool = True,
    use_gk: bool = False,
    use_exp2: bool = True,
    transpose_state: bool = False,
    qk_l2norm: bool = False,
    gate_in_kernel: bool = False,
    has_dt_bias: bool = False,
    beta_sigmoid_in_kernel: bool = False,
    output_final_state: bool = True,
    cp_context: bool = False,
    cp_world_size: int = 2,
    cp_rank: int = 1,
) -> List[torch.Tensor]:
    ...


@compile_ops("module_gdn_ck", fc_name="ck_gdn_decode")
def _ck_gdn_decode(
    q: torch.Tensor,
    k: torch.Tensor,
    v: torch.Tensor,
    g: Optional[torch.Tensor],
    beta: torch.Tensor,
    gk: Optional[torch.Tensor] = None,
    gv: Optional[torch.Tensor] = None,
    a_log: Optional[torch.Tensor] = None,
    dt_bias: Optional[torch.Tensor] = None,
    initial_state: Optional[torch.Tensor] = None,
    cu_seqlens: Optional[torch.Tensor] = None,
    scale: Optional[float] = None,
    use_g: bool = True,
    use_gk: bool = False,
    use_gv: bool = False,
    beta_headwise: bool = True,
    use_qk_l2norm: bool = False,
    use_exp2: bool = False,
    transpose_state: bool = False,
    gate_in_kernel: bool = False,
    has_dt_bias: bool = False,
    store_final_state: bool = True,
    validate_varlen: bool = True,
) -> List[torch.Tensor]:
    ...


def ck_gdn_prefill_workspace_bytes(
    q: torch.Tensor,
    v: torch.Tensor,
    cu_seqlens: Optional[torch.Tensor] = None,
    use_g: bool = True,
    use_gk: bool = False,
    use_exp2: bool = True,
    transpose_state: bool = False,
    qk_l2norm: bool = False,
    gate_in_kernel: bool = False,
    has_dt_bias: bool = False,
    beta_sigmoid_in_kernel: bool = False,
    output_final_state: bool = True,
    cp_context: bool = False,
    cp_world_size: int = 2,
) -> int:
    """Bytes required for :func:`ck_gdn_prefill`'s flat workspace tensor.

    Derived from the same tensors and flags as the launch entry, so the size and
    the launch can never disagree. Call it again whenever shape or flags change.
    """
    return int(
        _ck_gdn_prefill_workspace_bytes(
            q,
            v,
            cu_seqlens,
            use_g=use_g,
            use_gk=use_gk,
            use_exp2=use_exp2,
            transpose_state=transpose_state,
            qk_l2norm=qk_l2norm,
            gate_in_kernel=gate_in_kernel,
            has_dt_bias=has_dt_bias,
            beta_sigmoid_in_kernel=beta_sigmoid_in_kernel,
            output_final_state=output_final_state,
            cp_context=cp_context,
            cp_world_size=cp_world_size,
        )
    )


def ck_gdn_prefill_alloc_workspace(
    q: torch.Tensor,
    v: torch.Tensor,
    cu_seqlens: Optional[torch.Tensor] = None,
    **flags,
) -> torch.Tensor:
    """Convenience helper: allocate the flat workspace on ``q``'s device.

    The buffer is a plain ``uint8`` tensor so callers can cache and reuse it
    across layers/calls (that is the point of passing it explicitly).
    """
    size = ck_gdn_prefill_workspace_bytes(q, v, cu_seqlens, **flags)
    return torch.empty(size, dtype=torch.uint8, device=q.device)


def ck_gdn_prefill(
    q: torch.Tensor,
    k: torch.Tensor,
    v: torch.Tensor,
    g: Optional[torch.Tensor],
    beta: torch.Tensor,
    workspace: Optional[torch.Tensor] = None,
    gk: Optional[torch.Tensor] = None,
    a_log: Optional[torch.Tensor] = None,
    dt_bias: Optional[torch.Tensor] = None,
    initial_state: Optional[torch.Tensor] = None,
    cu_seqlens: Optional[torch.Tensor] = None,
    scale: Optional[float] = None,
    use_g: bool = True,
    use_gk: bool = False,
    use_exp2: bool = True,
    transpose_state: bool = False,
    qk_l2norm: bool = False,
    gate_in_kernel: bool = False,
    has_dt_bias: bool = False,
    beta_sigmoid_in_kernel: bool = False,
    output_final_state: bool = True,
    cp_context: bool = False,
    cp_world_size: int = 2,
    cp_rank: int = 1,
) -> Tuple[torch.Tensor, Optional[torch.Tensor]]:
    """CK GDN prefill pipeline, mirroring ``tile_example_gdn_prefill``.

    Shapes (packed, no batch dimension):

    * ``q``, ``k``: ``[tokens, h_qk, 128]`` fp16/bf16
    * ``v``: ``[tokens, h_v, 128]`` fp16/bf16
    * ``g``: ``[tokens, h_v]`` fp32 log-decay (required when ``use_g``)
    * ``gk``: ``[tokens, h_v, 128]`` fp32 per-key decay (required when ``use_gk``)
    * ``beta``: ``[tokens, h_v]`` fp32; raw values when
      ``beta_sigmoid_in_kernel`` else already sigmoid-applied
    * ``a_log``/``dt_bias``: ``[h_v]`` fp32, ``gate_in_kernel`` path
    * ``initial_state``: ``[sequences, h_v, 128, 128]`` fp32
    * ``cu_seqlens``: ``[sequences + 1]`` int64; supply it for packed varlen
      (a single-sequence list is normalised to the fixed-length path)
    * ``workspace``: flat ``uint8`` tensor, see
      :func:`ck_gdn_prefill_workspace_bytes`. Pass ``None`` (default) to let the
      adapter allocate one from the same flags; pass an explicit buffer to cache
      and reuse it across calls, which is the intended production path.

    Returns ``(output, final_state)`` with ``output`` shaped
    ``[tokens, h_v, 128]`` and ``final_state`` ``[sequences, h_v, 128, 128]``
    fp32, or ``None`` when ``output_final_state`` is false.
    """
    output, final_state = _ck_gdn_prefill(
        q,
        k,
        v,
        g,
        beta,
        workspace,
        gk,
        a_log,
        dt_bias,
        initial_state,
        cu_seqlens,
        scale,
        use_g=use_g,
        use_gk=use_gk,
        use_exp2=use_exp2,
        transpose_state=transpose_state,
        qk_l2norm=qk_l2norm,
        gate_in_kernel=gate_in_kernel,
        has_dt_bias=has_dt_bias,
        beta_sigmoid_in_kernel=beta_sigmoid_in_kernel,
        output_final_state=output_final_state,
        cp_context=cp_context,
        cp_world_size=cp_world_size,
        cp_rank=cp_rank,
    )
    if final_state is not None and final_state.numel() == 0:
        final_state = None
    return output, final_state


def ck_gdn_decode(
    q: torch.Tensor,
    k: torch.Tensor,
    v: torch.Tensor,
    g: Optional[torch.Tensor],
    beta: torch.Tensor,
    gk: Optional[torch.Tensor] = None,
    gv: Optional[torch.Tensor] = None,
    a_log: Optional[torch.Tensor] = None,
    dt_bias: Optional[torch.Tensor] = None,
    initial_state: Optional[torch.Tensor] = None,
    cu_seqlens: Optional[torch.Tensor] = None,
    scale: Optional[float] = None,
    use_g: bool = True,
    use_gk: bool = False,
    use_gv: bool = False,
    beta_headwise: bool = True,
    use_qk_l2norm: bool = False,
    use_exp2: bool = False,
    transpose_state: bool = False,
    gate_in_kernel: bool = False,
    has_dt_bias: bool = False,
    store_final_state: bool = True,
    validate_varlen: bool = True,
) -> Tuple[torch.Tensor, Optional[torch.Tensor]]:
    """CK GDN fused recurrent decode, mirroring ``tile_example_gdn_decode``.

    Shapes (packed):

    * ``q``, ``k``: ``[tokens, h_qk, 128]`` fp16/bf16
    * ``v``: ``[tokens, h_v, 128]`` fp16/bf16
    * ``g``: ``[tokens, h_v]`` (dtype code taken from the tensor)
    * ``gk``, ``gv``: ``[tokens, h_v]`` optional extra decays
    * ``beta``: ``[tokens, h_v]``; ``beta_headwise`` selects one BETA per value
      head, which is what the vLLM/SGLang paths use
    * ``initial_state``: ``[sequences, h_v, 128, 128]`` fp32
    * ``cu_seqlens``: ``[sequences + 1]`` int64. Supply it for packed inputs;
      without it the whole packed range is treated as one sequence. Fixed
      multi-batch inputs are expressed by equal-length entries.

    Returns ``(output, final_state)`` with ``output`` shaped
    ``[tokens, h_v, 128]`` and ``final_state`` ``[sequences, h_v, 128, 128]``
    fp32, or ``None`` when ``store_final_state`` is false.

    Note: CK has no state-pool index argument. A state pool must be gathered on
    the Python side before the call and scattered back afterwards.

    ``validate_varlen=False`` skips the host-side ``cu_seqlens`` checks. Those
    checks are the only reason this entry needs the values on the host, so they
    cost a device->host copy plus a stream sync on every call; production
    callers that own ``cu_seqlens`` should turn them off once and keep them off.
    The kernel reads ``cu_seqlens`` on device either way, so the result is the
    same.
    """
    output, final_state = _ck_gdn_decode(
        q,
        k,
        v,
        g,
        beta,
        gk,
        gv,
        a_log,
        dt_bias,
        initial_state,
        cu_seqlens,
        scale,
        use_g=use_g,
        use_gk=use_gk,
        use_gv=use_gv,
        beta_headwise=beta_headwise,
        use_qk_l2norm=use_qk_l2norm,
        use_exp2=use_exp2,
        transpose_state=transpose_state,
        gate_in_kernel=gate_in_kernel,
        has_dt_bias=has_dt_bias,
        store_final_state=store_final_state,
        validate_varlen=validate_varlen,
    )
    if final_state is not None and final_state.numel() == 0:
        final_state = None
    return output, final_state


__all__ = [
    "ck_gdn_prefill_workspace_bytes",
    "ck_gdn_prefill_alloc_workspace",
    "ck_gdn_prefill",
    "ck_gdn_decode",
]
