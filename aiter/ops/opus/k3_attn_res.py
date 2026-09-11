# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.

import functools
from enum import IntEnum

import torch
from torch import Tensor

from ...jit.core import compile_ops
from ...jit.utils.chip_info import get_gfx


@compile_ops("module_opus_k3_attn_res", fc_name="opus_k3_attn_res_hcu")
def _opus_k3_attn_res_hcu(
    prefix: Tensor,
    delta: Tensor,
    blocks: Tensor,
    norm_weight: Tensor,
    qk_weight: Tensor,
    output_norm_weight: Tensor,
    output: Tensor,
    num_blocks: int,
    block_write_idx: int,
    eps: float,
    output_norm_eps: float,
    kernel_id: int,
) -> None: ...


@functools.lru_cache(maxsize=1)
def _require_supported_arch() -> None:
    targets = {
        target.strip().lower().split(":", 1)[0]
        for group in str(get_gfx()).split(";")
        for target in group.split(",")
        if target.strip()
    }
    supported = {"gfx936", "gfx946"}
    if targets.isdisjoint(supported):
        raise NotImplementedError(
            "opus_k3_attn_res currently supports gfx936 and gfx946 "
            f"(detected GPU_ARCHS/rocminfo target(s): {sorted(targets)})"
        )


class OpusK3AttnResKernel(IntEnum):
    """Kimi K3 AttnRes 要跑哪条 fused kernel。生产路径请用 ``None`` / ``AUTO``。

    主形状（hidden=7168、8 blocks、无 delta/block-write、output RMSNorm、16 字节对齐）
    的自动选择：

    - tokens < 25            -> ``DECODE_SPLIT``
    - 25 <= tokens < 96      -> ``DECODE``
    - 96 <= tokens < 8192    -> ``PREFILL``
    - tokens >= 8192         -> ``LARGE_BATCH``

    gfx936 的其他 16 字节对齐形状走 ``ALIGNED_GENERAL``，其余走
    ``FALLBACK``；gfx946 当前统一走 ``FALLBACK``。
    整数值仍可传入，与成员取值相同。
    """

    # 按输入形状自动选择。等同于不传 kernelId。
    AUTO = -1
    # 通用回退：make_layout / make_gmem，覆盖未对齐行与任意 hidden / blocks。
    FALLBACK = 0
    # 16 字节对齐的通用接口。delta / block-write / output RMSNorm / num_blocks
    # 编译期钉死；hidden=4096 再钉 HiddenSize，decode 用 512 线程和 SourceTile=4
    # （与 Triton 的 num_warps=8 / BLOCK_L=4 相同）。
    ALIGNED_GENERAL = 1
    # 深 decode：把一个 token 的 hidden 切到 14 个 64 线程 workgroup。主形状 tokens < 25。
    DECODE_SPLIT = 2
    # decode：512 线程、每轮 3 个 source，循环卷起。主形状 25 <= tokens < 96。
    DECODE = 3
    # 256 线程预填充，SingleExp + 折叠 output RMSNorm。主形状 96 <= tokens < 8192。
    PREFILL = 4
    # 同 PREFILL 几何，仅折叠 output RMSNorm。主形状 tokens >= 8192。
    LARGE_BATCH = 5


def _resolve_opus_k3_attn_res_kernel_id(
    kernel_id: OpusK3AttnResKernel | int | str | None,
) -> int:
    return int(_resolve_opus_k3_attn_res_kernel(kernel_id))


def _resolve_opus_k3_attn_res_kernel(
    kernel_id: OpusK3AttnResKernel | int | str | None,
) -> OpusK3AttnResKernel:
    if kernel_id is None:
        return OpusK3AttnResKernel.AUTO
    if isinstance(kernel_id, OpusK3AttnResKernel):
        return kernel_id
    if isinstance(kernel_id, str):
        text = kernel_id.strip()
        if text.lower() in ("auto", "none"):
            return OpusK3AttnResKernel.AUTO
        key = text.upper()
        if key in OpusK3AttnResKernel.__members__:
            return OpusK3AttnResKernel[key]
        try:
            kernel_id = int(text)
        except ValueError as exc:
            names = ", ".join(OpusK3AttnResKernel.__members__)
            raise NotImplementedError(
                "kernelId must be None, OpusK3AttnResKernel, or one of " + names
            ) from exc
    try:
        return OpusK3AttnResKernel(int(kernel_id))
    except ValueError as exc:
        names = ", ".join(OpusK3AttnResKernel.__members__)
        raise NotImplementedError(
            "kernelId must be None, OpusK3AttnResKernel, or one of " + names
        ) from exc


def opus_k3_attn_res(
    prefix: Tensor,
    delta: Tensor | None,
    blocks: Tensor,
    norm_weight: Tensor,
    qk_weight: Tensor,
    output_norm_weight: Tensor | None,
    num_blocks: int,
    block_write_idx: int,
    eps: float,
    output_norm_eps: float,
    *,
    kernelId: OpusK3AttnResKernel | int | None = None,
) -> Tensor:
    """Run the fused Kimi K3 Attention Residuals operator on gfx936/gfx946.

    The first ten arguments match vLLM's AMD ``attn_res`` interface. Sources
    are ``blocks[:, :num_blocks]`` followed by the updated prefix. Each source
    is RMS-normalized for scoring, softmax is taken over depth sources, and the
    probabilities weight the original source values.

    If ``delta`` is provided, ``prefix += delta`` is rounded to BF16 and written
    back before mixing. ``block_write_idx >= 0`` writes that updated prefix into
    the block bank. ``output_norm_weight`` enables a final RMSNorm.

    ``kernelId=None`` (or ``OpusK3AttnResKernel.AUTO``) is the normal automatic
    path. On gfx936, the aligned K3 main shape selects ``DECODE_SPLIT`` below
    25 tokens, ``DECODE`` from 25 to 95, ``PREFILL`` from 96 to 8191, and
    ``LARGE_BATCH`` at or above 8192. Until gfx946-specific performance gates
    are complete, gfx946 automatic selection conservatively uses ``FALLBACK``.
    gfx946 permits explicit ``ALIGNED_GENERAL`` for correctness validation and
    uses a target-specific BF16 RNE lowering; the other optimized candidates
    remain rejected rather than returning unchecked results.

    Pass an ``OpusK3AttnResKernel`` member to pin a kernel. Integers matching
    those members remain accepted.
    """
    _require_supported_arch()
    kernel_id = _resolve_opus_k3_attn_res_kernel_id(kernelId)
    if prefix.dim() != 2:
        raise ValueError(f"prefix must be [tokens, hidden], got {tuple(prefix.shape)}")
    if blocks.dim() != 3:
        raise ValueError(
            f"blocks must be [tokens, capacity, hidden], got {tuple(blocks.shape)}"
        )
    if prefix.dtype != torch.bfloat16:
        raise NotImplementedError(f"prefix must be BF16, got {prefix.dtype}")
    required = (blocks, norm_weight, qk_weight)
    if any(t.dtype != torch.bfloat16 for t in required):
        raise NotImplementedError("blocks, norm_weight and qk_weight must be BF16")
    if any(not t.is_cuda or t.device != prefix.device for t in (prefix, *required)):
        raise ValueError("all required tensors must be on the same GPU")
    if prefix.stride(-1) != 1 or blocks.stride(-1) != 1:
        raise NotImplementedError("prefix and blocks must be contiguous in hidden")
    if norm_weight.dim() != 1 or qk_weight.dim() != 1:
        raise ValueError("norm_weight and qk_weight must be 1D")

    num_tokens, hidden_size = prefix.shape
    if hidden_size <= 0 or hidden_size > 8192:
        raise ValueError("hidden size must be in [1, 8192]")
    if blocks.shape[0] != num_tokens or blocks.shape[2] != hidden_size:
        raise ValueError("blocks shape must be [tokens, capacity, hidden]")
    if norm_weight.numel() != hidden_size or qk_weight.numel() != hidden_size:
        raise ValueError("weight lengths must equal hidden size")
    block_capacity = blocks.shape[1]
    if not 0 <= int(num_blocks) <= min(8, block_capacity):
        raise ValueError("num_blocks must be in [0, min(8, block capacity)]")
    if block_write_idx != -1 and not 0 <= int(block_write_idx) < block_capacity:
        raise ValueError("block_write_idx must be -1 or within block capacity")

    empty = torch.empty((0,), device=prefix.device, dtype=prefix.dtype)
    delta_arg = empty
    if delta is not None:
        if delta.dtype != torch.bfloat16 or not delta.is_cuda:
            raise NotImplementedError("delta must be a BF16 GPU tensor")
        if delta.device != prefix.device or delta.shape != prefix.shape:
            raise ValueError("delta must match prefix shape and device")
        if delta.stride(-1) != 1:
            raise NotImplementedError("delta must be contiguous in hidden")
        delta_arg = delta

    output_norm_arg = empty
    if output_norm_weight is not None:
        if (
            output_norm_weight.dtype != torch.bfloat16
            or not output_norm_weight.is_cuda
        ):
            raise NotImplementedError("output_norm_weight must be a BF16 GPU tensor")
        if output_norm_weight.device != prefix.device:
            raise ValueError("output_norm_weight must be on the prefix device")
        if output_norm_weight.dim() != 1 or output_norm_weight.numel() != hidden_size:
            raise ValueError("output_norm_weight must be [hidden]")
        output_norm_arg = output_norm_weight

    output = torch.empty(prefix.shape, device=prefix.device, dtype=prefix.dtype)
    if num_tokens == 0:
        return output
    _opus_k3_attn_res_hcu(
        prefix,
        delta_arg,
        blocks,
        norm_weight,
        qk_weight,
        output_norm_arg,
        output,
        int(num_blocks),
        int(block_write_idx),
        float(eps),
        float(output_norm_eps),
        kernel_id,
    )
    return output
