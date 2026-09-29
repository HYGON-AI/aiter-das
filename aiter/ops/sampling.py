# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
# SPDX-License-Identifier: MIT

import functools
from typing import Optional, Tuple, Union

import torch

from ..jit.core import compile_ops


@compile_ops("module_sampling", fc_name="top_k_sampling_from_probs")
def c_top_k_sampling_from_probs(
    probs: torch.Tensor,
    output: torch.Tensor,
    maybe_indices: Optional[torch.Tensor],
    maybe_top_k_arr: Optional[torch.Tensor],
    top_k_val: int,
    deterministic: bool,
    philox_seed: int,
    philox_offset: int,
) -> None:
    pass


@compile_ops("module_sampling", fc_name="top_p_sampling_from_probs")
def c_top_p_sampling_from_probs(
    probs: torch.Tensor,
    output: torch.Tensor,
    maybe_indices: Optional[torch.Tensor],
    maybe_top_p_arr: Optional[torch.Tensor],
    top_p_val: float,
    deterministic: bool,
    philox_seed: int,
    philox_offset: int,
) -> None:
    pass


@compile_ops("module_sampling", fc_name="top_k_top_p_sampling_from_probs")
def c_top_k_top_p_sampling_from_probs(
    probs: torch.Tensor,
    output: torch.Tensor,
    maybe_indices: Optional[torch.Tensor],
    maybe_top_k_arr: Optional[torch.Tensor],
    top_k_val: int,
    maybe_top_p_arr: Optional[torch.Tensor],
    top_p_val: float,
    deterministic: bool,
    philox_seed: int,
    philox_offset: int,
) -> None:
    pass


@functools.cache
def _default_generator(device: torch.device):
    torch.cuda.init()
    return torch.cuda.default_generators[device.index]


def _get_seed_and_offset(
    increment: int,
    generator: Optional[torch.Generator],
    device: torch.device,
) -> Tuple[int, int]:
    if generator is None:
        generator = _default_generator(device)
    state = generator.get_state()
    seed, offset = state.view(torch.int64)
    offset += (increment + 3) // 4 * 4
    generator.set_state(
        torch.tensor(
            [seed, offset], dtype=torch.int64, device=torch.device("cpu")
        ).view(torch.uint8)
    )
    return int(seed), int(offset)


def _prepare_batch(
    probs: torch.Tensor,
    indices: Optional[torch.Tensor],
) -> Tuple[torch.Tensor, torch.Tensor, int]:
    device = probs.device
    probs = probs.float().contiguous()
    batch_size = indices.size(0) if indices is not None else probs.size(0)
    out_dtype = indices.dtype if indices is not None else torch.int32
    samples = torch.empty(batch_size, dtype=out_dtype, device=device)
    return probs, samples, batch_size


def top_k_sampling_from_probs(
    probs: torch.Tensor,
    top_k: Union[torch.Tensor, int],
    indices: Optional[torch.Tensor] = None,
    deterministic: bool = True,
    generator: Optional[torch.Generator] = None,
    check_nan: bool = False,
    seed: Optional[int] = None,
    offset: Optional[int] = None,
) -> torch.Tensor:
    if check_nan and torch.any(torch.isnan(probs)):
        raise ValueError("Input probs contains NaN.")
    probs, samples, batch_size = _prepare_batch(probs, indices)
    if seed is None or offset is None:
        seed, offset = _get_seed_and_offset(batch_size * 32, generator, probs.device)

    if isinstance(top_k, torch.Tensor):
        c_top_k_sampling_from_probs(
            probs, samples, indices, top_k.to(torch.int32).contiguous(), 0,
            deterministic, seed, offset,
        )
    else:
        c_top_k_sampling_from_probs(
            probs, samples, indices, None, int(top_k),
            deterministic, seed, offset,
        )
    return samples


def top_p_sampling_from_probs(
    probs: torch.Tensor,
    top_p: Union[torch.Tensor, float],
    indices: Optional[torch.Tensor] = None,
    deterministic: bool = True,
    generator: Optional[torch.Generator] = None,
    check_nan: bool = False,
    seed: Optional[int] = None,
    offset: Optional[int] = None,
) -> torch.Tensor:
    if check_nan and torch.any(torch.isnan(probs)):
        raise ValueError("Input probs contains NaN.")
    probs, samples, batch_size = _prepare_batch(probs, indices)
    if seed is None or offset is None:
        seed, offset = _get_seed_and_offset(batch_size * 32, generator, probs.device)

    if isinstance(top_p, torch.Tensor):
        c_top_p_sampling_from_probs(
            probs, samples, indices, top_p.float().contiguous(), 0.0,
            deterministic, seed, offset,
        )
    else:
        c_top_p_sampling_from_probs(
            probs, samples, indices, None, float(top_p),
            deterministic, seed, offset,
        )
    return samples


def top_k_top_p_sampling_from_probs(
    probs: torch.Tensor,
    top_k: Union[torch.Tensor, int],
    top_p: Union[torch.Tensor, float],
    indices: Optional[torch.Tensor] = None,
    filter_apply_order: str = "joint",
    deterministic: bool = True,
    generator: Optional[torch.Generator] = None,
    check_nan: bool = False,
    seed: Optional[int] = None,
    offset: Optional[int] = None,
) -> torch.Tensor:
    if filter_apply_order != "joint":
        raise NotImplementedError(
            "Only filter_apply_order='joint' is supported."
        )
    if check_nan and torch.any(torch.isnan(probs)):
        raise ValueError("Input probs contains NaN.")
    probs, samples, batch_size = _prepare_batch(probs, indices)
    if seed is None or offset is None:
        seed, offset = _get_seed_and_offset(batch_size * 32, generator, probs.device)

    top_k_tensor = top_k.to(torch.int32).contiguous() if isinstance(top_k, torch.Tensor) else None
    top_k_scalar = 0 if isinstance(top_k, torch.Tensor) else int(top_k)
    top_p_tensor = top_p.float().contiguous() if isinstance(top_p, torch.Tensor) else None
    top_p_scalar = 0.0 if isinstance(top_p, torch.Tensor) else float(top_p)

    c_top_k_top_p_sampling_from_probs(
        probs, samples, indices,
        top_k_tensor, top_k_scalar,
        top_p_tensor, top_p_scalar,
        deterministic, seed, offset,
    )
    return samples
