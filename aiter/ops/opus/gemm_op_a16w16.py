# SPDX-License-Identifier: MIT
# Copyright (C) 2025-2026, Advanced Micro Devices, Inc. All rights reserved.
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.

import functools

import torch
from torch import Tensor

from ...jit.core import compile_ops
from ...jit.utils.chip_info import get_gfx


@compile_ops(
    "module_deepgemm_opus",
    fc_name="opus_gemm_a16w16_hcu",
)
def _opus_gemm_a16w16_hcu(
    XQ: Tensor,
    WQ: Tensor,
    Y: Tensor,
    Bias: Tensor,
    Workspace: Tensor,
    split_k: int,
    kernel_id: int,
) -> None: ...


@functools.lru_cache(maxsize=1)
def _normalized_gfx_targets() -> frozenset[str]:
    return frozenset(
        target.strip().lower().split(":", 1)[0]
        for group in str(get_gfx()).split(";")
        for target in group.split(",")
        if target.strip()
    )


@functools.lru_cache(maxsize=1)
def _require_supported_hcu_arch() -> frozenset[str]:
    targets = _normalized_gfx_targets()
    if not targets.intersection({"gfx936", "gfx938", "gfx946"}):
        raise NotImplementedError(
            "gemm_a16w16_opus only supports gfx936, gfx938 and gfx946 "
            f"(detected GPU_ARCHS/rocminfo target(s): {sorted(targets)})"
        )
    return targets


def gemm_a16w16_opus(
    A: Tensor,
    B: Tensor,
    bias=None,
    dtype=torch.bfloat16,
    *,
    kernelId=None,
    splitK=None,
    out: Tensor | None = None,
) -> Tensor:
    """Run a Hygon gfx936/gfx938/gfx946 BF16 Opus GEMM.

    Computes ``A @ B.transpose(-1, -2)``.  A may be ``[M, K]`` or
    ``[batch, M, K]``; B may be ``[N, K]`` or ``[batch, N, K]``.

    Kernel selection:

    - ``kernelId=None``: automatic selection (recommended for normal use).
    - ``kernelId=0``: direct global-memory baseline.
    - ``kernelId=1``: 16x16 synchronous-LDS baseline.
    - ``kernelId=2``: 32x32 four-wave LDS kernel; on gfx938 this may use
      automatic split-K for low-parallelism, long-K shapes.
    - ``kernelId=3``: 64x64x32 layout-driven Opus pipeline with VGPR
      prefetch and double-buffered LDS.

    On gfx936/gfx938, automatic selection uses kernel 3 for sufficiently large, aligned work
    (M/N divisible by 64, K divisible by 32, at least 16 block tiles), except
    for low-parallelism long-K shapes reserved for the existing split-K path.
    Other shapes fall back to kernel 2 on eligible gfx938 workloads or kernel
    0. gfx946 keeps kernel 0 as the conservative automatic default until a
    real-device performance gate is available; explicit ``kernelId`` values
    always override this policy.

    ``splitK=None`` uses the automatic policy; an explicit positive value
    overrides it. Kernel 3 requires ``splitK <= K // 32``. Bias may be ``[N]``
    or ``[batch, N]`` and may use BF16 or FP32 storage.
    """
    targets = _require_supported_hcu_arch()
    kernel_id = None if kernelId is None else int(kernelId)
    if kernel_id is not None and kernel_id not in (0, 1, 2, 3):
        raise NotImplementedError(
            "kernelId must be 0 (direct), 1 (LDS 16x16), 2 (LDS 32x32), "
            "or 3 (Opus 64x64x32 pipeline)"
        )
    if A.dtype != torch.bfloat16 or B.dtype != torch.bfloat16:
        raise NotImplementedError(
            f"gemm_a16w16_opus only supports BF16 A/B, got {A.dtype=} and {B.dtype=}"
        )
    if dtype not in (torch.bfloat16, torch.float32):
        raise NotImplementedError(f"only BF16 and FP32 output are supported, got {dtype}")
    if not A.is_cuda or not B.is_cuda or A.device != B.device:
        raise ValueError("A and B must be on the same GPU")
    if not A.is_contiguous() or not B.is_contiguous():
        raise NotImplementedError("A and B must be contiguous")

    if A.dim() == 2:
        M, K = A.shape
        XQ = A.unsqueeze(0)
        return_2d = True
    elif A.dim() == 3:
        batch, M, K = A.shape
        XQ = A
        return_2d = False
    else:
        raise ValueError(f"A must be 2D or 3D, got shape {tuple(A.shape)}")
    batch = XQ.shape[0]
    if B.dim() == 2:
        N, K_b = B.shape
        WQ = B.unsqueeze(0)
    elif B.dim() == 3:
        b_batch, N, K_b = B.shape
        if b_batch not in (1, batch):
            raise ValueError(f"B batch must be 1 or {batch}, got {b_batch}")
        WQ = B
    else:
        raise ValueError(f"B must be 2D or 3D, got shape {tuple(B.shape)}")
    if K_b != K:
        raise ValueError(f"A/B K mismatch: {K} vs {K_b}")

    if kernel_id is None:
        opus_block_tiles = batch * (M // 64) * (N // 64)
        use_opus_pipeline = (
            "gfx946" not in targets
            and M % 64 == 0
            and N % 64 == 0
            and K % 32 == 0
            and M * N * K >= 256**3
            and opus_block_tiles >= 16
            # Preserve the previously tuned split-K policy for low-parallelism,
            # long-K shapes until kernelId=3 receives a dedicated split-K tune.
            and not (K >= 2048 and opus_block_tiles <= 128)
        )
        use_lds_32x32 = (
            "gfx938" in targets
            and M >= 32
            and N >= 32
            and (M * N * K >= 512**3 or K >= 2048)
        )
        kernel_id = 3 if use_opus_pipeline else (2 if use_lds_32x32 else 0)

    if splitK is None:
        output_tiles = batch * ((M + 31) // 32) * ((N + 31) // 32)
        split_k = (
            8
            if kernel_id == 2
            and "gfx938" in targets
            and K >= 2048
            and output_tiles <= 512
            else 1
        )
    else:
        split_k = int(splitK)
    if split_k < 1:
        raise ValueError("splitK must be positive")
    if split_k > (K + 15) // 16:
        raise ValueError("splitK cannot exceed the number of 16-element K tiles")
    if kernel_id == 3:
        if M % 64 or N % 64:
            raise ValueError("kernelId 3 requires M and N divisible by 64")
        if K % 32:
            raise ValueError("kernelId 3 requires K divisible by 32")
        if split_k > K // 32:
            raise ValueError(
                "kernelId 3 splitK cannot exceed the number of 32-element K tiles"
            )

    if bias is None:
        Bias = torch.empty((0,), dtype=torch.float32, device=A.device)
    else:
        if not bias.is_cuda or bias.device != A.device:
            raise ValueError("bias must be on the same GPU as A")
        if bias.dtype not in (torch.bfloat16, torch.float32):
            raise ValueError("bias must be BF16 or FP32")
        if not bias.is_contiguous():
            raise NotImplementedError("bias must be contiguous")
        if bias.dim() == 1:
            if tuple(bias.shape) != (N,):
                raise ValueError(f"1D bias shape must be ({N},)")
        elif bias.dim() == 2:
            if tuple(bias.shape) != (batch, N):
                raise ValueError(f"2D bias shape must be ({batch}, {N})")
        else:
            raise ValueError("bias must be 1D [N] or 2D [batch, N]")
        Bias = bias

    expected_shape = (batch, M, N)
    if out is None:
        Y = torch.empty(expected_shape, dtype=dtype, device=A.device)
    else:
        expected_out_shape = (M, N) if return_2d else expected_shape
        if out.device != A.device or out.dtype != dtype:
            raise ValueError("out must use the requested dtype and the same device as A")
        if tuple(out.shape) != expected_out_shape:
            raise ValueError(f"out shape must be {expected_out_shape}")
        if not out.is_contiguous():
            raise NotImplementedError("out must be contiguous")
        Y = out.unsqueeze(0) if return_2d and out.dim() == 2 else out

    Workspace = (
        torch.empty((split_k, batch, M, N), dtype=torch.float32, device=A.device)
        if split_k > 1
        else torch.empty((0,), dtype=torch.float32, device=A.device)
    )
    _opus_gemm_a16w16_hcu(XQ, WQ, Y, Bias, Workspace, split_k, kernel_id)
    return Y.squeeze(0) if return_2d else Y
