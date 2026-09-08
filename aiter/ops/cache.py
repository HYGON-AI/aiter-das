# SPDX-License-Identifier: MIT
# Copyright (C) 2024-2026, Advanced Micro Devices, Inc. All rights reserved.
from torch import Tensor
from ..jit.core import compile_ops

MD_NAME = "module_cache"


@compile_ops("module_cache")
def swap_blocks(src: Tensor, dst: Tensor, block_mapping: Tensor) -> None: ...


@compile_ops("module_cache")
def copy_blocks(
    key_caches: Tensor, value_caches: Tensor, block_mapping: Tensor
) -> None: ...


@compile_ops("module_cache")
def reshape_and_cache(
    key: Tensor,
    value: Tensor,
    key_cache: Tensor,
    value_cache: Tensor,
    slot_mapping: Tensor,
    kv_cache_dtype: str,
    k_scale: float,
    v_scale: float,
    asm_layout: bool,
) -> None: ...


@compile_ops("module_cache")
def reshape_and_cache_flash(
    key: Tensor,
    value: Tensor,
    key_cache: Tensor,
    value_cache: Tensor,
    slot_mapping: Tensor,
    kv_cache_dtype: str,
    k_scale: Tensor,
    v_scale: Tensor,
) -> None: ...


@compile_ops("module_cache")
def reshape_and_cache_with_pertoken_quant(
    key: Tensor,
    value: Tensor,
    key_cache: Tensor,
    value_cache: Tensor,
    k_dequant_scales: Tensor,
    v_dequant_scales: Tensor,
    slot_mapping: Tensor,
    asm_layout: bool,
) -> None: ...


@compile_ops("module_cache")
def reshape_and_cache_with_block_quant(
    key: Tensor,
    value: Tensor,
    key_cache: Tensor,
    value_cache: Tensor,
    k_dequant_scales: Tensor,
    v_dequant_scales: Tensor,
    slot_mapping: Tensor,
    asm_layout: bool,
) -> None: ...


@compile_ops("module_cache")
def convert_fp8(
    dst_cache: Tensor, src_cache: Tensor, scale: float, kv_cache_dtype: str
) -> None: ...

@compile_ops("module_cache")
def store_kv_cache(
    packed_qkv: Tensor,
    k_cache: Tensor,
    v_cache: Tensor,
    q_lens: Tensor,
    accum_q_lens: Tensor,
    cache_lens: Tensor,
    cache_slot_ids: Tensor,
    k_scale: Tensor,
    v_scale: Tensor,
    kv_cache_dtype: str,
    q_head_num: int,
    kv_head_num: int,
) -> None: ...


@compile_ops("module_cache")
def store_kv_cache_paged(
    key: Tensor,
    value: Tensor,
    k_cache: Tensor,
    v_cache: Tensor,
    q_lens: Tensor,
    accum_q_lens: Tensor,
    cache_lens: Tensor,
    block_table: Tensor,
    k_scale: Tensor,
    v_scale: Tensor,
    kv_cache_dtype: str,
) -> None: ...
