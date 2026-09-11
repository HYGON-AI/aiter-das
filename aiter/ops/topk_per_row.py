# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
# SPDX-License-Identifier: MIT
"""Per-row TopK (k=2048) from topk_per_row.cu."""

from typing import Optional

import torch

from ..jit.core import compile_ops

TOPK = 2048


@compile_ops("module_prefer_hipcc")
def top_k_per_row_prefill(
    logits: torch.Tensor,
    rowStarts: torch.Tensor,
    rowEnds: torch.Tensor,
    indices: torch.Tensor,
    numRows: int,
    stride0: int,
    stride1: int,
    values: Optional[torch.Tensor] = None,
) -> None:
    pass


@compile_ops("module_prefer_hipcc")
def top_k_per_row_decode(
    logits: torch.Tensor,
    next_n: int,
    seqLens: torch.Tensor,
    indices: torch.Tensor,
    numRows: int,
    stride0: int,
    stride1: int,
) -> None:
    pass


def topk_per_row_prefill(
    logits: torch.Tensor,
    row_starts: torch.Tensor,
    row_ends: torch.Tensor,
    *,
    return_values: bool = False,
) -> tuple[torch.Tensor, Optional[torch.Tensor]]:
    """
    Prefill TopK (k=2048) over [row_starts[i], row_ends[i]) per row.

    Args:
        logits: float32 scores of shape [num_rows, stride0]
        row_starts / row_ends: int32 [num_rows]
        return_values: if True, also write top-k values

    Returns:
        indices [num_rows, 2048] (int32), and optionally values [num_rows, 2048]
    """
    assert logits.dtype == torch.float32
    assert logits.dim() == 2
    num_rows = logits.size(0)
    stride0 = logits.stride(0)
    stride1 = logits.stride(1)
    indices = torch.empty((num_rows, TOPK), dtype=torch.int32, device=logits.device)
    values = (
        torch.empty((num_rows, TOPK), dtype=torch.float32, device=logits.device)
        if return_values
        else None
    )
    top_k_per_row_prefill(
        logits,
        row_starts,
        row_ends,
        indices,
        num_rows,
        stride0,
        stride1,
        values,
    )
    return indices, values


def topk_per_row_decode(
    logits: torch.Tensor,
    next_n: int,
    seq_lens: torch.Tensor,
) -> torch.Tensor:
    """
    Decode TopK (k=2048) for speculative / multi-token decode.

    For expanded row i (num_rows = batch * next_n):
        seq_len = seq_lens[i // next_n]
        row_end = seq_len - next_n + (i % next_n) + 1
        topk over logits[i, 0:row_end]

    Returns:
        indices [num_rows, 2048] (int32)
    """
    assert logits.dtype == torch.float32
    assert logits.dim() == 2
    assert next_n >= 1
    num_rows = logits.size(0)
    stride0 = logits.stride(0)
    stride1 = logits.stride(1)
    indices = torch.empty((num_rows, TOPK), dtype=torch.int32, device=logits.device)
    top_k_per_row_decode(
        logits,
        next_n,
        seq_lens,
        indices,
        num_rows,
        stride0,
        stride1,
    )
    return indices
