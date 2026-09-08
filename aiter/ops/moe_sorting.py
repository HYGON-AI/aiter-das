# SPDX-License-Identifier: MIT
# Copyright (C) 2024-2025, Advanced Micro Devices, Inc. All rights reserved.
import torch
from typing import Optional
from ..jit.core import compile_ops

MD_NAME = "module_cpp_api"


@compile_ops("module_cpp_api")
def moe_sorting_fwd(
    topk_ids: torch.Tensor,
    topk_weights: torch.Tensor,
    sorted_token_ids: torch.Tensor,
    sorted_weights: torch.Tensor,
    sorted_expert_ids: torch.Tensor,
    tokens_positions_per_expert: torch.Tensor,
    num_valid_ids: torch.Tensor,
    moe_buf: Optional[torch.Tensor],
    num_experts: int,
    unit_size: int,
    local_expert_mask: Optional[torch.Tensor] = None,
) -> None:
    """Sort routes, ignoring IDs outside [0, num_experts), including padding -1.

    Valid ranks/weights are preserved. num_valid_ids is the padded entry count.
    tokens_positions_per_expert contains E local counts (masked=0), then E
    exclusive padded offsets in global expert order, including empty experts.
    local_expert_mask is an int32 0/1 mask. All tensors must be contiguous and
    on the same GPU; IDs/metadata are int32 and weights are float32.
    Work is enqueued on the current stream. moe_buf, if supplied, is zeroed
    and must have a 16-byte aligned address and byte size. M=0 is supported.
    """
    ...


@compile_ops(MD_NAME)
def moe_sorting_ck_ids_to_moe_c(
    ck_sorted_token_ids: torch.Tensor,
    moe_c_sorted_token_ids: torch.Tensor,
    num_tokens: int,
    topk: int,
) -> None: ...
