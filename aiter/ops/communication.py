# SPDX-License-Identifier: MIT
# Copyright (C) 2024-2026, Advanced Micro Devices, Inc. All rights reserved.
import torch
from torch import Tensor
import torch.distributed as dist
from ..dist.parallel_state import (
    ensure_model_parallel_initialized,
    init_distributed_environment,
    set_custom_all_reduce,
    get_tp_group,
    destroy_model_parallel,
    destroy_distributed_environment,
)
from ..dist.utils import get_open_port, get_distributed_init_method, get_ip
import aiter
import logging

logger = logging.getLogger("aiter")


def init_dist_env(
    world_size: int | None = None,
    rankID: int | None = None,
    backend: str = "cpu:gloo,cuda:nccl",
    distributed_init_method: str | None = "env://",
    local_rank: int = -1,
    data_parallel_size: int = 1,
    data_parallel_rank: int = 0,
    decode_context_parallel_size: int = 1,
    prefill_context_model_parallel_size: int = 1,
    *,
    tensor_model_parallel_size: int | None = None,
    pipeline_model_parallel_size: int = 1,
    custom_group_config=None,
):
    """Initialize TP/DP/EP/PP/context groups; ``world_size`` retains its old TP meaning.

    All ranks must use the same rendezvous (env:// or an explicit shared URL).
    With DP > 1, rankID is the rank within TP*PP*PCP and data_parallel_rank
    supplies the outer DP coordinate, matching init_distributed_environment.
    """
    if tensor_model_parallel_size is not None:
        if world_size is not None and world_size != tensor_model_parallel_size:
            raise ValueError("world_size and tensor_model_parallel_size disagree")
        world_size = tensor_model_parallel_size
    if world_size is None or world_size <= 0 or rankID is None:
        raise ValueError("positive TP size and rankID are required")
    tp = world_size
    world_size = tp * pipeline_model_parallel_size * prefill_context_model_parallel_size
    set_custom_all_reduce(True)
    init_distributed_environment(world_size=world_size, rank=rankID,
        distributed_init_method=distributed_init_method, backend=backend,
        local_rank=local_rank, data_parallel_size=data_parallel_size,
        data_parallel_rank=data_parallel_rank)
    ensure_model_parallel_initialized(tp, pipeline_model_parallel_size,
        data_parallel_size=data_parallel_size, custom_group_config=custom_group_config,
        decode_context_model_parallel_size=decode_context_parallel_size,
        prefill_context_model_parallel_size=prefill_context_model_parallel_size)
    logger.debug("RANK: %s TP=%s init_dist_env", rankID, tp)


def destroy_dist_env():
    if dist.is_initialized():
        destroy_model_parallel()
        destroy_distributed_environment()
        torch.cuda.empty_cache()

"""
def all_reduce_asm(inp: torch.Tensor):
    tp_grp = get_tp_group()
    ca = tp_grp.ca_comm

    if ca._IS_CAPTURING:
        if torch.cuda.is_current_stream_capturing():
            return aiter.all_reduce_asm_(
                inp, ca._ptr, ca.signal, ca.buffer, ca._IS_CAPTURING
            )
        else:
            # if warm up, mimic the allocation pattern
            # since custom allreduce is out-of-place
            return torch.empty_like(inp)
    else:
        # note: outside of cuda graph context,
        # custom allreduce incurs a cost of cudaMemcpy, which should
        # be small(<=1% of overall latency) compared to the performance
        # gains of using custom kernels
        return aiter.all_reduce_asm_(
            inp, ca._ptr, ca.signal, ca.buffer, ca._IS_CAPTURING
        )


def all_reduce_rmsnorm(
    input: Tensor, residual_in: Tensor, weight: Tensor, bias: Tensor, epsilon: float
):
    tp_grp = get_tp_group()
    ca = tp_grp.ca_comm

    return aiter.all_reduce_rmsnorm_(
        input,
        residual_in,
        weight,
        bias,
        epsilon,
        ca._ptr,
        ca.signal,
        ca.buffer,
        ca._IS_CAPTURING,
    )


def all_reduce_rmsnorm_quant(
    input: Tensor,
    residual_in: Tensor,
    xscale: Tensor,
    weight: Tensor,
    bias: Tensor,
    epsilon: float,
):
    tp_grp = get_tp_group()
    ca = tp_grp.ca_comm

    return aiter.all_reduce_rmsnorm_quant_(
        input,
        residual_in,
        xscale,
        weight,
        bias,
        epsilon,
        ca._ptr,
        ca.signal,
        ca.buffer,
        ca._IS_CAPTURING,
    )
"""
