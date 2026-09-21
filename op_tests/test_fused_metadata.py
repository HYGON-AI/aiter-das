# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
# SPDX-License-Identifier: MIT
"""
Correctness & benchmark tests for ``aiter.fused_metadata_kernel_general``.

三方对拍基准：Triton 参考内核（``_fused_metadata_kernel_general_triton``）vs
AITER CUDA kernel vs 纯 PyTorch 参考（``ref_copy``），输出按 ``torch.equal``
逐 buffer 全量比对。计时走 module_kvcache 的裸 pybind 绑定（``_get_aiter_fn``，
绕过 torch.ops dispatcher 约 10us 的 Python 开销），CUDA-event 计时口径为
warmup=20 / iters=200 / batch=10 取中位数，与 LightOp 迁移前一致。

CLI 测试组（--case，按测试方向分组，定义见文件头部）：

  * default  基线配置集（LightOp 源测试 test_configs 逐参数移植）
  * v1       规模扫描：B/P 端点、SWA 与路由分支相关配置
  * v2       page_size=1（SHIFT=0）快路径：尾部缺页 / 大 P / delta / SWA
  * v3       通用路径（page_size>1）：tail 整行重写 / SWA / delta
  * v4       int4 快路径对齐与布局：16B 对齐 / 非连续 req_to_token
  * v5       契约负向：page_size 校验 + 输出 dtype/contiguity/shape
  * v6       内核结构边界：最小 launch / 扫描 lane / 组扫描 / XL 串行回退

数值组（default / v1-v4 / v6）每例做 -1 哨兵三方对拍 + event 计时；v5 为
异常组，仅断言 RuntimeError。

单配置选择：--case 支持 ``组名:序号`` 语法（序号 1-based，按组内 case 顺序，
如 ``--case v2:3`` 只运行 v2 组第 3 个配置）；``--list-cases`` 打印全部组内
case 的序号与参数后退出。pytest 侧经 @pytest.mark.parametrize 共享同一
份 case 定义（单 case 亦可用 node id 选择，如
``::test_suite_v2_shift0[ps=1 tail=2]``），另有 base matrix / SWA / dtype
组合三组独立参数化测试。

所有测试需要 CUDA 设备（Triton + AITER JIT）。
"""

import argparse
import functools
import math
import os
import sys

import pytest
import torch

import triton
import triton.language as tl

import aiter

# Source-tree root (the dir that CONTAINS the ``aiter`` package) this test file
# lives under:  aiter_0813/aiter/op_tests/test_*.py -> aiter_0813/aiter.
# ``import aiter`` must resolve here (run with PYTHONPATH set to _SRC_PARENT,
# as rebuild_fused_metadata.sh does); a stale site-packages copy predates the
# fused_metadata migration and fails with ModuleNotFoundError/AttributeError.
_SRC_PARENT = os.path.dirname(os.path.dirname(os.path.abspath(__file__)))


@functools.lru_cache(maxsize=1)
def _get_aiter_fn():
    """Return the raw module_kvcache binding, bypassing the torch.ops wrapper
    (see module docstring).  Equivalent to lightop's ``lightop.op.*`` path."""
    from aiter.jit.core import get_module
    try:
        md = get_module("module_kvcache")
    except Exception:
        if not hasattr(aiter, "fused_metadata_kernel_general"):
            # import resolved to a stale site-packages copy (predates the
            # fused_metadata migration): it can neither import nor build the
            # module, so fail with the exact fix instead of the AttributeError.
            raise RuntimeError(
                f"`import aiter` loaded the stale copy "
                f"{getattr(aiter, '__file__', '???')!r}, which has no "
                f"fused_metadata_kernel_general and no module_kvcache .so. "
                f"Run against the source tree instead:\n"
                f"    PYTHONPATH={_SRC_PARENT} python "
                f"{os.path.abspath(__file__)} [args]\n"
                f"(or rebuild via rebuild_fused_metadata.sh first)"
            ) from None
        # Not built yet -- trigger the JIT build via the public wrapper once.
        kw = make_inputs(B=1, num_reqs=1, max_seq_pages=4, page_size=1,
                         seq_len_delta=0)
        aiter.fused_metadata_kernel_general(**kw)
        md = get_module("module_kvcache")
    return md.fused_metadata_kernel_general


# ---------------------------------------------------------------------------
# CLI 测试组定义（--case，按测试方向分组）。CLI 与 pytest 参数化共享同一份
# 定义，全部置于文件头部以供 pytest 收集阶段（import 时求值的
# @pytest.mark.parametrize）引用。
# 数值组（default / v1 / v2 / v3 / v4 / v6）：每例做 -1 哨兵三方对拍 +
# CUDA-event 计时；v5 异常组：仅断言 RuntimeError，不计性能。
# ---------------------------------------------------------------------------
_CASE_DESCRIPTIONS = {
    'default': '基线配置集（LightOp 源测试逐参数移植）',
    'v1':      '规模扫描：B/P 端点、SWA 与路由分支相关配置',
    'v2':      'page_size=1（SHIFT=0）快路径：尾部缺页 / 大 P / delta / SWA',
    'v3':      '通用路径（page_size>1）：tail 整行重写 / SWA / delta',
    'v4':      'int4 快路径对齐与布局：16B 对齐 / 非连续 req_to_token',
    'v5':      '契约负向：page_size 校验 + 输出 dtype/contiguity/shape',
    'v6':      '内核结构边界：最小 launch / 扫描 lane / 组扫描 / XL 串行回退',
}

# default：基线配置集 —— LightOp 源测试 main() test_configs 逐参数移植，
# 迁移前后性能可直接对比。
DEFAULT_CASES = [
    dict(B=1,  num_reqs=64,  max_seq_pages=512,  page_size=32, seq_len_delta=0, use_swa=False, note='B=1 P=512 ps=32'),
    dict(B=2,  num_reqs=64,  max_seq_pages=512,  page_size=32, seq_len_delta=0, use_swa=False, note='B=2 P=512 ps=32'),
    dict(B=4,  num_reqs=64,  max_seq_pages=512,  page_size=32, seq_len_delta=0, use_swa=False, note='B=4 P=512 ps=32'),
    dict(B=8,  num_reqs=64,  max_seq_pages=512,  page_size=32, seq_len_delta=0, use_swa=False, note='B=8 P=512 ps=32'),
    dict(B=16, num_reqs=64,  max_seq_pages=512,  page_size=32, seq_len_delta=0, use_swa=False, note='B=16 P=512 ps=32'),
    dict(B=32, num_reqs=64,  max_seq_pages=512,  page_size=32, seq_len_delta=0, use_swa=False, note='B=32 P=512 ps=32'),
    dict(B=64, num_reqs=128, max_seq_pages=1024, page_size=32, seq_len_delta=0, use_swa=False, note='B=64 P=1024 ps=32'),
    dict(B=4,  num_reqs=64,  max_seq_pages=512,  page_size=32, seq_len_delta=0, use_swa=True,  note='B=4 P=512 ps=32 swa'),
    dict(B=8,  num_reqs=64,  max_seq_pages=512,  page_size=32, seq_len_delta=0, use_swa=True,  note='B=8 P=512 ps=32 swa'),
    dict(B=8,  num_reqs=64,  max_seq_pages=4096, page_size=1,  seq_len_delta=0, use_swa=False, note='B=8 P=4096 ps=1'),
    dict(B=8,  num_reqs=64,  max_seq_pages=512,  page_size=32, seq_len_delta=4, use_swa=False, note='B=8 P=512 ps=32 delta=4'),
]

# v1 规模扫描：B/P 端点与路由分支相关配置（原 --small/--large 配置集融入），
# 并新增 B 扫描中间点与路由矩阵补点（wg=256 阈值两侧、WG 512 段）。
V1_SUITE = [
    dict(B=2,   num_reqs=8,   max_seq_pages=64,   page_size=16, seq_len_delta=0, use_swa=False, note='scale B=2 small'),
    dict(B=4,   num_reqs=8,   max_seq_pages=64,   page_size=16, seq_len_delta=0, use_swa=True,  note='scale B=4 small swa'),
    dict(B=8,   num_reqs=64,  max_seq_pages=2048, page_size=32, seq_len_delta=0, use_swa=False, note='scale B=8 P=2048'),
    dict(B=8,   num_reqs=128, max_seq_pages=4096, page_size=32, seq_len_delta=0, use_swa=False, note='scale B=8 P=4096 R=128'),
    dict(B=16,  num_reqs=64,  max_seq_pages=512,  page_size=16, seq_len_delta=0, use_swa=False, note='scale B=16 P=512'),
    dict(B=32,  num_reqs=64,  max_seq_pages=1024, page_size=16, seq_len_delta=0, use_swa=False, note='scale B=32 P=1024'),
    dict(B=64,  num_reqs=128, max_seq_pages=4096, page_size=16, seq_len_delta=0, use_swa=False, note='scale B=64 P=4096'),
    dict(B=128, num_reqs=128, max_seq_pages=2048, page_size=16, seq_len_delta=0, use_swa=False, note='scale B=128 P=2048 routing boundary'),
    dict(B=128, num_reqs=128, max_seq_pages=4096, page_size=16, seq_len_delta=0, use_swa=False, note='scale B=128 P=4096'),
    dict(B=128, num_reqs=128, max_seq_pages=4096, page_size=16, seq_len_delta=0, use_swa=True,  note='scale B=128 P=4096 swa'),
    dict(B=256, num_reqs=128, max_seq_pages=4096, page_size=16, seq_len_delta=0, use_swa=False, note='scale B=256 P=4096'),
    dict(B=128, num_reqs=128, max_seq_pages=8192, page_size=16, seq_len_delta=0, use_swa=False, note='scale B=128 P=8192'),
]

# v2 SHIFT=0 快路径（page_size=1）：尾部缺页（P % 4 != 0）哨兵预填 + 全量对拍，
# 覆盖大 P 与 delta/SWA 叠加。
V2_SUITE = [
    dict(B=1, num_reqs=8,  max_seq_pages=5,    page_size=1, seq_len_delta=0, use_swa=False, note='ps=1 tail=1'),
    dict(B=1, num_reqs=8,  max_seq_pages=6,    page_size=1, seq_len_delta=0, use_swa=False, note='ps=1 tail=2'),
    dict(B=2, num_reqs=8,  max_seq_pages=7,    page_size=1, seq_len_delta=0, use_swa=False, note='ps=1 tail=3 B>1'),
    dict(B=2, num_reqs=8,  max_seq_pages=5,    page_size=1, seq_len_delta=0, use_swa=True,  note='ps=1 tail=1 swa'),
    dict(B=1, num_reqs=8,  max_seq_pages=1025, page_size=1, seq_len_delta=0, use_swa=False, note='ps=1 tail=1 large P'),
    dict(B=2, num_reqs=8,  max_seq_pages=1026, page_size=1, seq_len_delta=0, use_swa=False, note='ps=1 tail=2 large P'),
    dict(B=4, num_reqs=16, max_seq_pages=1027, page_size=1, seq_len_delta=4, use_swa=True,  note='ps=1 tail=3 delta swa'),
    dict(B=2, num_reqs=8,  max_seq_pages=512,  page_size=1, seq_len_delta=0, use_swa=False, note='ps=1 no-tail boundary'),
    dict(B=8, num_reqs=64, max_seq_pages=1024, page_size=1, seq_len_delta=0, use_swa=False, note='ps=1 P=1024 no-tail'),
    dict(B=8, num_reqs=64, max_seq_pages=4096, page_size=1, seq_len_delta=0, use_swa=False, note='ps=1 P=4096 dense'),
]

# v3 通用路径（page_size>1）：tail 整行重写（写流量敏感），覆盖 SWA / delta。
V3_SUITE = [
    dict(B=8,  num_reqs=64,  max_seq_pages=1024, page_size=32, seq_len_delta=0, use_swa=False, note='ps=32 no-tail baseline'),
    dict(B=8,  num_reqs=64,  max_seq_pages=1025, page_size=32, seq_len_delta=0, use_swa=False, note='ps=32 tail=1'),
    dict(B=8,  num_reqs=64,  max_seq_pages=1026, page_size=32, seq_len_delta=0, use_swa=False, note='ps=32 tail=2'),
    dict(B=4,  num_reqs=64,  max_seq_pages=511,  page_size=16, seq_len_delta=0, use_swa=True,  note='ps=16 tail=3 swa'),
    dict(B=16, num_reqs=64,  max_seq_pages=2049, page_size=16, seq_len_delta=0, use_swa=False, note='ps=16 tail=1 large B'),
    dict(B=1,  num_reqs=64,  max_seq_pages=1,    page_size=32, seq_len_delta=0, use_swa=False, note='ps=32 pure tail'),
    dict(B=2,  num_reqs=8,   max_seq_pages=512,  page_size=32, seq_len_delta=0, use_swa=False, note='ps=32 no-tail boundary'),
    dict(B=4,  num_reqs=64,  max_seq_pages=512,  page_size=32, seq_len_delta=4, use_swa=False, note='ps=32 delta=4'),
]

# v4 int4 快路径对齐与布局：page_size=1，行宽 == max_tokens；pool indices 选中
# （非）16B 对齐行或非连续 req_to_token（对齐前提由 _build_alignment_kw 断言固定）。
V4_SUITE = [
    dict(B=2, num_reqs=8, max_tokens=1022, first_pool_idx=1, seq_len_delta=0, use_swa=False, noncontig=False, note='unaligned 1022'),
    dict(B=2, num_reqs=8, max_tokens=1023, first_pool_idx=1, seq_len_delta=0, use_swa=False, noncontig=False, note='unaligned 1023'),
    dict(B=2, num_reqs=8, max_tokens=1024, first_pool_idx=1, seq_len_delta=0, use_swa=False, noncontig=False, note='aligned 1024'),
    dict(B=4, num_reqs=8, max_tokens=1022, first_pool_idx=1, seq_len_delta=0, use_swa=True,  noncontig=False, note='unaligned swa'),
    dict(B=4, num_reqs=8, max_tokens=1023, pool_indices=[0, 1, 3, 2], seq_len_delta=0, use_swa=False, noncontig=False, note='mixed rows'),
    dict(B=2, num_reqs=8, max_tokens=512, seq_len_delta=0, use_swa=False, noncontig=True, note='non-contiguous r2t'),
    dict(B=2, num_reqs=8, max_tokens=1022, first_pool_idx=1, seq_len_delta=4, use_swa=False, noncontig=False, note='unaligned delta4'),
]

# v5 契约负向：非法 page_size 与输出 dtype/contiguity/shape 契约，每个 case
# 只破坏一项，期望 C++ launcher 抛 RuntimeError（不计性能）。
V5_INVALID_PAGE_SIZES = [0, -1, 3, 6, 10]
V5_CONTRACT_CASES = [
    'page_table_int64_dtype',
    'cache_seqlens_int64_dtype',
    'cu_seqlens_k_non_contiguous',
    'page_table_non_contiguous',
    'swa_page_table_int64_dtype',
    'req_to_token_int64_dtype',
    'page_table_wrong_shape',
    'mapping_float32_dtype',
    'use_swa_missing_swa_page_table',
    'use_swa_missing_mapping',
]

# v6 内核结构边界：最小 launch（B=1 P=1）、2D tail（grid_y=2）、64-lane 扫描
# 边界、组扫描组边界（B=64/65/128）、B>1024 串行回退。B=0/P=0 由 host
# TORCH_CHECK（shape [0]/[B+1]）拒绝构造，无法在本 harness 覆盖。
V6_SUITE = [
    dict(B=1,    num_reqs=8,   max_seq_pages=1,    page_size=1,  seq_len_delta=0, use_swa=False, note='minimal B=1 P=1 ps=1'),
    dict(B=1,    num_reqs=8,   max_seq_pages=259,  page_size=1,  seq_len_delta=0, use_swa=False, note='2D tail P=259 (grid_y=2)'),
    dict(B=3,    num_reqs=8,   max_seq_pages=67,   page_size=2,  seq_len_delta=0, use_swa=False, note='B=3 ps=2 unaligned tail'),
    dict(B=63,   num_reqs=64,  max_seq_pages=257,  page_size=32, seq_len_delta=0, use_swa=False, note='B=63 last scan lane + tail'),
    dict(B=64,   num_reqs=128, max_seq_pages=1024, page_size=32, seq_len_delta=0, use_swa=True,  note='B=64 grouped scan 1 group swa'),
    dict(B=65,   num_reqs=128, max_seq_pages=64,   page_size=16, seq_len_delta=0, use_swa=False, note='B=65 grouped scan 2nd group=1 row'),
    dict(B=128,  num_reqs=128, max_seq_pages=4096, page_size=16, seq_len_delta=0, use_swa=False, note='B=128 grouped scan 2 groups'),
    dict(B=1025, num_reqs=128, max_seq_pages=16,   page_size=1,  seq_len_delta=0, use_swa=False, note='B=1025 serial fallback (XL)'),
]


# ---------------------------------------------------------------------------
# Triton reference kernel (copied verbatim from the LightOp source test so the
# semantics stay identical).
# ---------------------------------------------------------------------------
@triton.jit
def _fused_metadata_kernel_general_triton(
    seq_lens, seq_lens_stride_0,
    req_to_token, req_to_token_stride_0, req_to_token_stride_1,
    req_pool_indices, req_pool_indices_stride_0,
    cache_seqlens_int32, cache_seqlens_int32_stride_0,
    cu_seqlens_k, cu_seqlens_k_stride_0,
    page_table, page_table_stride_0, page_table_stride_1,
    swa_page_table, swa_page_table_stride_0, swa_page_table_stride_1,
    full_to_swa_mapping, full_to_swa_mapping_stride_0,
    B, max_seq_pages,
    page_size: tl.constexpr,
    seq_len_delta: tl.constexpr,
    use_swa: tl.constexpr,
    SHIFT: tl.constexpr,
    BLOCK_COLS: tl.constexpr,
):
    pid_b = tl.program_id(0)
    pid_c = tl.program_id(1)

    if pid_b == 0 and pid_c == 0:
        acc = 0
        for idx in range(B):
            seq = tl.load(seq_lens + idx * seq_lens_stride_0)
            val = (seq + seq_len_delta).to(tl.int32)
            tl.store(cache_seqlens_int32 + idx * cache_seqlens_int32_stride_0, val)
            tl.store(cu_seqlens_k + idx * cu_seqlens_k_stride_0, acc)
            acc += val
        tl.store(cu_seqlens_k + B * cu_seqlens_k_stride_0, acc)

    if max_seq_pages == 0:
        return

    i = pid_b
    row_idx = tl.load(req_pool_indices + i * req_pool_indices_stride_0)
    row_offset = row_idx * req_to_token_stride_0

    col_start = pid_c * BLOCK_COLS
    col_offsets = col_start + tl.arange(0, BLOCK_COLS)
    mask = col_offsets < max_seq_pages

    if page_size == 1:
        col_idx = col_offsets
    else:
        col_idx = col_offsets << SHIFT

    rt_offsets = row_offset + col_idx * req_to_token_stride_1
    page_index = tl.load(req_to_token + rt_offsets, mask=mask, other=0, cache_modifier=".cg")

    if page_size == 1:
        page_table_val = page_index
    else:
        page_table_val = page_index >> SHIFT

    pt_offsets = i * page_table_stride_0 + col_offsets * page_table_stride_1
    tl.store(page_table + pt_offsets, page_table_val, mask=mask, cache_modifier=".cg")

    if use_swa:
        swa_slot = tl.load(
            full_to_swa_mapping + page_index * full_to_swa_mapping_stride_0,
            mask=mask, other=0, cache_modifier=".cg",
        )
        if page_size == 1:
            swa_val = swa_slot
        else:
            swa_val = swa_slot >> SHIFT
        swa_offsets = i * swa_page_table_stride_0 + col_offsets * swa_page_table_stride_1
        tl.store(swa_page_table + swa_offsets, swa_val, mask=mask, cache_modifier=".cg")


def run_triton(
    seq_lens,
    req_to_token,
    req_pool_indices,
    cache_seqlens_int32,
    cu_seqlens_k,
    page_table,
    swa_page_table=None,
    full_to_swa_mapping=None,
    B=None,
    max_seq_pages=None,
    page_size=1,
    seq_len_delta=0,
    use_swa=False,
    BLOCK_COLS=128,
):
    if B is None:
        B = seq_lens.size(0)
    if max_seq_pages is None:
        max_seq_pages = page_table.size(1)

    SHIFT = 0
    if page_size > 1:
        SHIFT = int(math.log2(page_size))

    grid = (B, triton.cdiv(max_seq_pages, BLOCK_COLS))

    _fused_metadata_kernel_general_triton[grid](
        seq_lens, seq_lens.stride(0),
        req_to_token, req_to_token.stride(0), req_to_token.stride(1),
        req_pool_indices, req_pool_indices.stride(0),
        cache_seqlens_int32, cache_seqlens_int32.stride(0),
        cu_seqlens_k, cu_seqlens_k.stride(0),
        page_table, page_table.stride(0), page_table.stride(1),
        swa_page_table, swa_page_table.stride(0) if swa_page_table is not None else 0,
        swa_page_table.stride(1) if swa_page_table is not None else 0,
        full_to_swa_mapping, full_to_swa_mapping.stride(0) if full_to_swa_mapping is not None else 0,
        B, max_seq_pages,
        page_size=page_size,
        seq_len_delta=seq_len_delta,
        use_swa=use_swa,
        SHIFT=SHIFT,
        BLOCK_COLS=BLOCK_COLS,
    )


# ---------------------------------------------------------------------------
# Input generation and pure-PyTorch reference.
# ---------------------------------------------------------------------------
def make_inputs(B, num_reqs, max_seq_pages, page_size, seq_len_delta,
                device='cuda', use_swa=False,
                seq_lens_dtype=torch.int32, pool_dtype=torch.int32,
                mapping_dtype=torch.int32):
    """Create fixed-seed inputs for reproducible benchmarking / correctness.

    ``seq_lens_dtype`` / ``pool_dtype`` are the dtypes of ``seq_lens`` and
    ``req_pool_indices`` (int32 or int64); ``mapping_dtype`` is the dtype of
    ``full_to_swa_mapping`` (int32 or int64).  ``req_to_token`` and all output
    buffers are always int32.
    """
    max_tokens = max_seq_pages * page_size
    torch.manual_seed(42)
    # seq_lens must be >= 1; guard max_seq_pages*page_size == 1 (hi == low).
    seq_hi = max(max_tokens // 2 + 1, 2)
    seq_lens = torch.randint(1, seq_hi, (B,), dtype=seq_lens_dtype, device=device)
    req_to_token = torch.randint(0, max_tokens, (num_reqs, max_tokens), dtype=torch.int32, device=device)
    req_pool_indices = torch.randint(0, num_reqs, (B,), dtype=pool_dtype, device=device)

    cache_seqlens_int32 = torch.empty(B, dtype=torch.int32, device=device)
    cu_seqlens_k = torch.empty(B + 1, dtype=torch.int32, device=device)
    page_table = torch.empty(B, max_seq_pages, dtype=torch.int32, device=device)

    swa_page_table = None
    full_to_swa_mapping = None
    if use_swa:
        swa_page_table = torch.empty(B, max_seq_pages, dtype=torch.int32, device=device)
        full_to_swa_mapping = torch.randint(0, max_tokens, (max_tokens,), dtype=mapping_dtype, device=device)

    return dict(
        seq_lens=seq_lens, req_to_token=req_to_token,
        req_pool_indices=req_pool_indices,
        cache_seqlens_int32=cache_seqlens_int32,
        cu_seqlens_k=cu_seqlens_k,
        page_table=page_table,
        swa_page_table=swa_page_table,
        full_to_swa_mapping=full_to_swa_mapping,
        B=B, max_seq_pages=max_seq_pages,
        page_size=page_size, seq_len_delta=seq_len_delta,
        use_swa=use_swa,
    )


def ref_copy(kw):
    """纯 PyTorch 参考（向量化；dtype 语义与内核一致）。

    ``cache_seqlens_int32`` 恒转 int32（seq_lens 为 int64 时同样）；页索引按
    整除（而非移位）除以 page_size。token 列偏移 c*page_size 恒小于行宽
    （c < P），无需越界 guard。
    """
    B = kw['B']
    page_size = kw['page_size']
    device = kw['seq_lens'].device

    cs = (kw['seq_lens'] + kw['seq_len_delta']).to(torch.int32)
    cu = torch.zeros(B + 1, dtype=torch.int64, device=device)
    cu[1:] = torch.cumsum(cs, dim=0, dtype=torch.int64)
    cu = cu.to(torch.int32)

    rows = kw['req_pool_indices'].long().unsqueeze(1)                  # [B, 1]
    cols = (torch.arange(kw['page_table'].size(1), device=device)
            * page_size).unsqueeze(0)                                  # [1, P]
    idx = kw['req_to_token'][rows, cols]                               # [B, P]
    result = dict(cache_seqlens_int32=cs, cu_seqlens_k=cu,
                  page_table=(idx // page_size).to(torch.int32))
    if kw['use_swa']:
        result['swa_page_table'] = (
            kw['full_to_swa_mapping'][idx] // page_size).to(torch.int32)
    return result


# ---------------------------------------------------------------------------
# Three-way comparison harness.
# ---------------------------------------------------------------------------
def _clone_kw(kw):
    return {k: (v.clone() if isinstance(v, torch.Tensor) else v) for k, v in kw.items()}


def _collect_outputs(d):
    """Copy the in-place written output buffers out of a run."""
    out = {
        'cache_seqlens_int32': d['cache_seqlens_int32'].clone(),
        'cu_seqlens_k': d['cu_seqlens_k'].clone(),
        'page_table': d['page_table'].clone(),
    }
    if d['swa_page_table'] is not None:
        out['swa_page_table'] = d['swa_page_table'].clone()
    return out


def run_three_way(kw, page_table_sentinel=None):
    """Run Triton, AITER and the PyTorch reference on identical inputs and
    assert all outputs match ``torch.equal`` exactly.

    If ``page_table_sentinel`` is not None, the ``page_table`` (and
    ``swa_page_table`` when used) buffers are pre-filled with the sentinel
    value before each launch, so any page the kernel fails to write still holds
    the sentinel and the reference comparison fails loudly -- this is what
    makes the tail cases catch *partial* tail drops (e.g. 1026 pages).
    """
    def fresh():
        d = _clone_kw(kw)
        if page_table_sentinel is not None:
            d['page_table'].fill_(page_table_sentinel)
            if d['swa_page_table'] is not None:
                d['swa_page_table'].fill_(page_table_sentinel)
        return d

    # Triton reference run.
    it = fresh()
    run_triton(**it)
    triton_out = _collect_outputs(it)

    # AITER CUDA run.
    ia = fresh()
    _get_aiter_fn()(**ia)
    aiter_out = _collect_outputs(ia)

    # Pure-PyTorch reference (reads the original inputs, ignores output buffers).
    ref = ref_copy(kw)

    for key in triton_out:
        assert torch.equal(triton_out[key], ref[key]), \
            f"TRITON vs REF mismatch on '{key}': " \
            f"max_diff={(triton_out[key].long() - ref[key].long()).abs().max().item()}"
        assert torch.equal(aiter_out[key], ref[key]), \
            f"AITER  vs REF mismatch on '{key}': " \
            f"max_diff={(aiter_out[key].long() - ref[key].long()).abs().max().item()}"


# ---------------------------------------------------------------------------
# 正确性 base matrix：B x page_size x max_seq_pages x use_swa x seq_len_delta
# 代表配置扫描（page_size=1 / >1、SWA、delta!=0、B 与 max_seq_pages 两端）。
# ---------------------------------------------------------------------------
@pytest.mark.parametrize(
    "B,num_reqs,max_seq_pages,page_size,seq_len_delta,use_swa",
    [
        (1,   64, 64,    1,   0, False),   # B=1, page_size=1
        (2,   64, 64,    16,  0, False),   # B=2, page_size=16
        (4,   64, 64,    32,  0, False),   # B=4, page_size=32
        (8,   64, 512,   32,  0, False),
        (16,  64, 512,   16,  0, True),    # SWA, page_size>1
        (32,  64, 512,   32,  4, False),   # seq_len_delta != 0
        (64,  128, 1024, 1,   0, True),    # SWA, page_size=1
        (128, 128, 2048, 32,  0, False),   # B=128
        (8,   64, 4096,  1,   0, False),   # page_size=1, max_seq_pages=4096
        (64,  128, 4096, 16,  0, False),   # max_seq_pages=4096, page_size=16
        (16,  64, 1024,  1,   4, True),    # page_size=1 + delta + SWA
        (8,   64, 1024,  32,  0, False),
        (32,  128, 2048, 16,  0, False),
    ],
)
def test_correctness_base_matrix(B, num_reqs, max_seq_pages, page_size,
                                 seq_len_delta, use_swa):
    kw = make_inputs(B=B, num_reqs=num_reqs, max_seq_pages=max_seq_pages,
                     page_size=page_size, seq_len_delta=seq_len_delta,
                     use_swa=use_swa)
    run_three_way(kw)


# ---------------------------------------------------------------------------
# v1-v6 测试组（pytest 参数化；case 定义与 CLI --case 共享）。
# 数值组做 -1 哨兵三方对拍；v5 异常组断言 RuntimeError。
# ---------------------------------------------------------------------------
@pytest.mark.parametrize("case", V1_SUITE, ids=lambda c: c['note'])
def test_suite_v1_scale(case):
    """v1 规模扫描：B/P 端点与路由分支相关配置。"""
    run_three_way(_build_plain_kw(case), page_table_sentinel=-1)


@pytest.mark.parametrize("case", V2_SUITE, ids=lambda c: c['note'])
def test_suite_v2_shift0(case):
    """v2 SHIFT=0 快路径（page_size=1）：尾部缺页 + 大 P + delta/SWA。"""
    run_three_way(_build_plain_kw(case), page_table_sentinel=-1)


@pytest.mark.parametrize("case", V3_SUITE, ids=lambda c: c['note'])
def test_suite_v3_general(case):
    """v3 通用路径（page_size>1）：tail 整行重写 + SWA + delta。"""
    run_three_way(_build_plain_kw(case), page_table_sentinel=-1)


@pytest.mark.parametrize("case", V4_SUITE, ids=lambda c: c['note'])
def test_suite_v4_alignment(case):
    """v4 int4 快路径对齐/布局：含前置对齐断言。"""
    run_three_way(_build_alignment_kw(case), page_table_sentinel=-1)


@pytest.mark.parametrize("page_size", V5_INVALID_PAGE_SIZES)
def test_suite_v5_page_size_guard(page_size):
    """v5 负向：非法 page_size（0 / 负值 / 非 2 的幂）必须抛 RuntimeError。"""
    assert _expects_runtime_error(_build_invalid_ps_kw(page_size)), \
        f"page_size={page_size} should raise RuntimeError"


@pytest.mark.parametrize("case_id", V5_CONTRACT_CASES)
def test_suite_v5_output_contract(case_id):
    """v5 负向：破坏输出 dtype/contiguity/shape 契约必须抛 RuntimeError。"""
    assert _expects_runtime_error(_build_contract_kw(case_id)), \
        f"{case_id} should raise RuntimeError"


@pytest.mark.parametrize("case", V6_SUITE, ids=lambda c: c['note'])
def test_suite_v6_boundary(case):
    """v6 内核结构边界：最小 launch / 扫描 lane / 组扫描 / XL 回退。"""
    run_three_way(_build_plain_kw(case), page_table_sentinel=-1)


# ---------------------------------------------------------------------------
# SWA：page_size x mapping dtype x max_seq_pages 组合。page_size=1 时 SWA 页
# 表必须直接取 mapping 值（不移位）—— ref_copy 的 ``fts[idx] // page_size``
# 即该语义，三方对拍覆盖。
# ---------------------------------------------------------------------------
@pytest.mark.parametrize("max_seq_pages", [5, 6, 1024])
@pytest.mark.parametrize("mapping_dtype", [torch.int32, torch.int64])
@pytest.mark.parametrize("page_size", [1, 16, 32])
def test_swa(page_size, mapping_dtype, max_seq_pages):
    kw = make_inputs(B=4, num_reqs=64, max_seq_pages=max_seq_pages,
                     page_size=page_size, seq_len_delta=0, use_swa=True,
                     mapping_dtype=mapping_dtype)
    run_three_way(kw)


# ---------------------------------------------------------------------------
# dtype 组合：seq_lens / req_pool_indices x {int32,int64} 与
# full_to_swa_mapping x {int32,int64} —— 全部 8 种分派组合。
# ---------------------------------------------------------------------------
@pytest.mark.parametrize(
    "seq_lens_dtype,pool_dtype,mapping_dtype",
    [
        (torch.int32, torch.int32, torch.int32),
        (torch.int32, torch.int32, torch.int64),
        (torch.int32, torch.int64, torch.int32),
        (torch.int32, torch.int64, torch.int64),
        (torch.int64, torch.int32, torch.int32),
        (torch.int64, torch.int32, torch.int64),
        (torch.int64, torch.int64, torch.int32),
        (torch.int64, torch.int64, torch.int64),
    ],
)
def test_dtype_combos(seq_lens_dtype, pool_dtype, mapping_dtype):
    kw = make_inputs(B=4, num_reqs=64, max_seq_pages=64, page_size=16,
                     seq_len_delta=0, use_swa=True,
                     seq_lens_dtype=seq_lens_dtype, pool_dtype=pool_dtype,
                     mapping_dtype=mapping_dtype)
    run_three_way(kw)


# ---------------------------------------------------------------------------
# Performance: CUDA-event timing, warmup=20, iters=200, batch=10, median.
# The first call triggers Triton/AITER JIT compilation; the warmup loop is
# not timed, so compilation cost is excluded.
# ---------------------------------------------------------------------------
def benchmark_gpu_events(kw, fn, warmup=20, iters=200, batch=10):
    """Benchmark ``fn`` with CUDA events; returns median per-call ms.

    ``warmup`` runs are not timed (also cover first-call JIT compilation);
    ``iters`` timed calls are grouped in ``batch`` per CUDA-event pair and the
    per-call medians are taken over ``iters // batch`` samples.
    """
    inp = make_inputs(**kw)
    # Warmup (also covers first-call JIT compilation) -- not timed.
    for _ in range(warmup):
        inp_i = _clone_kw(inp)
        fn(**inp_i)

    # Pre-allocate once, reuse for all timed iterations.
    inp = make_inputs(**kw)
    start_event = torch.cuda.Event(enable_timing=True)
    end_event = torch.cuda.Event(enable_timing=True)

    times = []
    for _ in range(iters // batch):
        start_event.record()
        for _ in range(batch):
            fn(**inp)
        end_event.record()
        torch.cuda.synchronize()
        elapsed_ms = start_event.elapsed_time(end_event)
        times.append(elapsed_ms / batch)

    times.sort()
    return times[len(times) // 2]


# ---------------------------------------------------------------------------
# Case 构造 helpers（CLI 与 pytest 共享）。
# ---------------------------------------------------------------------------
def _build_plain_kw(case):
    """数值 case -> 输入 dict。"""
    return make_inputs(B=case['B'], num_reqs=case['num_reqs'],
                       max_seq_pages=case['max_seq_pages'],
                       page_size=case['page_size'],
                       seq_len_delta=case['seq_len_delta'],
                       use_swa=case['use_swa'])


def _build_alignment_kw(case):
    """v4 布局 case 输入：page_size=1，行宽 == max_tokens；通过固定
    req_pool_indices 选中（非）对齐行，或构造 stride(1)!=1 的非连续
    req_to_token。对齐前提以断言固定（构造失败即视为测试失败）。"""
    kw = make_inputs(B=case['B'], num_reqs=case['num_reqs'],
                     max_seq_pages=case['max_tokens'], page_size=1,
                     seq_len_delta=case['seq_len_delta'], use_swa=case['use_swa'])
    if case.get('noncontig'):
        base = torch.empty(case['num_reqs'], case['max_tokens'] * 2,
                           dtype=torch.int32, device='cuda')
        base[:, ::2].copy_(kw['req_to_token'])
        kw['req_to_token'] = base[:, ::2]  # stride(1) == 2
        return kw

    if case.get('pool_indices') is not None:
        kw['req_pool_indices'] = torch.tensor(case['pool_indices'],
                                              dtype=torch.int32, device='cuda')
    elif case.get('first_pool_idx') is not None:
        kw['req_pool_indices'][0] = case['first_pool_idx']

    offsets = [int(idx) * kw['req_to_token'].stride(0)
               for idx in kw['req_pool_indices']]
    if case['max_tokens'] % 4 == 0:
        assert all((o & 3) == 0 for o in offsets), \
            f"precondition: max_tokens={case['max_tokens']} expects aligned rows"
    else:
        assert any((o & 3) != 0 for o in offsets), \
            f"precondition: max_tokens={case['max_tokens']} needs an unaligned row"
        if case.get('pool_indices') is not None:
            # mixed-rows case：同批内必须同时存在对齐与非对齐行。
            assert any((o & 3) == 0 for o in offsets), \
                "precondition: mixed-rows case needs an aligned row too"
    return kw


def _build_invalid_ps_kw(page_size):
    """v5 非法 page_size case：只改 page_size，其余输入固定合法。"""
    kw = make_inputs(B=2, num_reqs=8, max_seq_pages=8, page_size=1,
                     seq_len_delta=0, use_swa=False)
    kw['page_size'] = page_size
    return kw


def _build_contract_kw(case_id):
    """v5 契约负向 case：基座 use_swa=True，每个 case 只破坏一项契约。"""
    base = make_inputs(B=4, num_reqs=64, max_seq_pages=64, page_size=16,
                       seq_len_delta=0, use_swa=True)
    kw = _clone_kw(base)
    dev = base['seq_lens'].device
    B = base['B']
    M = base['max_seq_pages']

    if case_id == 'page_table_int64_dtype':
        kw['page_table'] = kw['page_table'].to(torch.int64)
    elif case_id == 'cache_seqlens_int64_dtype':
        kw['cache_seqlens_int32'] = kw['cache_seqlens_int32'].to(torch.int64)
    elif case_id == 'cu_seqlens_k_non_contiguous':
        base_cu = torch.empty(2 * (B + 1), dtype=torch.int32, device=dev)
        kw['cu_seqlens_k'] = base_cu[::2]
    elif case_id == 'page_table_non_contiguous':
        base_pt = torch.empty(B, M * 2, dtype=torch.int32, device=dev)
        kw['page_table'] = base_pt[:, ::2]
    elif case_id == 'swa_page_table_int64_dtype':
        kw['swa_page_table'] = kw['swa_page_table'].to(torch.int64)
    elif case_id == 'req_to_token_int64_dtype':
        kw['req_to_token'] = kw['req_to_token'].to(torch.int64)
    elif case_id == 'page_table_wrong_shape':
        kw['page_table'] = torch.empty(B, M + 1, dtype=torch.int32, device=dev)
    elif case_id == 'mapping_float32_dtype':
        kw['full_to_swa_mapping'] = kw['full_to_swa_mapping'].float()
    elif case_id == 'use_swa_missing_swa_page_table':
        kw['swa_page_table'] = None
    elif case_id == 'use_swa_missing_mapping':
        kw['full_to_swa_mapping'] = None
    else:
        raise AssertionError(f'unknown exception case: {case_id}')
    return kw


def _expects_runtime_error(kw):
    """只有显式抛 RuntimeError 才算符合契约（负向用例通过条件）。"""
    try:
        _get_aiter_fn()(**kw)
    except RuntimeError:
        return True
    except Exception:
        return False
    return False


# 数值组 dispatch 表：case_id -> (case 列表, 构造函数)。
_NUMERIC_CASES = {
    'default': (DEFAULT_CASES, _build_plain_kw),
    'v1':      (V1_SUITE, _build_plain_kw),
    'v2':      (V2_SUITE, _build_plain_kw),
    'v3':      (V3_SUITE, _build_plain_kw),
    'v4':      (V4_SUITE, _build_alignment_kw),
    'v6':      (V6_SUITE, _build_plain_kw),
}

# v5 异常组有序条目（--list-cases 与 --case v5:N 共用同一编号）：先 page_size
# 后输出契约。
V5_ENTRIES = ([('page_size', ps) for ps in V5_INVALID_PAGE_SIZES]
              + [('contract', cid) for cid in V5_CONTRACT_CASES])


def _run_numeric_case(kw, case, bench_only, warmup=20, iters=200):
    """单个数值 case：-1 哨兵三方对拍 + event 计时，返回 (ok, triton_ms, aiter_ms)。"""
    ok = True
    if not bench_only:
        try:
            run_three_way(kw, page_table_sentinel=-1)
        except AssertionError:
            ok = False
    # 计时输入由 make_inputs(**cfg) 重建（v4 布局 case 的对齐微调不参与计时，
    # 只需同形输入；v4 case 用 max_tokens 表示行宽，折算回 max_seq_pages）。
    cfg = dict(B=case['B'], num_reqs=case['num_reqs'],
               max_seq_pages=case.get('max_seq_pages', case.get('max_tokens')),
               page_size=case.get('page_size', 1),
               seq_len_delta=case['seq_len_delta'], use_swa=case['use_swa'])
    t_triton = benchmark_gpu_events(cfg, run_triton, warmup=warmup, iters=iters)
    t_aiter = benchmark_gpu_events(cfg, _get_aiter_fn(), warmup=warmup, iters=iters)
    return ok, t_triton, t_aiter


def _write_traffic_note(kw):
    """v3 通用路径的写流量下限提示（page_table [+ swa_page_table] 全行重写）。"""
    writes = kw['B'] * kw['max_seq_pages'] * 4 * (2 if kw['use_swa'] else 1)
    return f" writes_min={writes // 1024}KB"


def _check_case_index(case_id, index, count):
    """校验 --case 组名:N 的 1-based 序号，越界时报错并退出。"""
    if not 1 <= index <= count:
        raise SystemExit(
            f"error: --case {case_id}:{index} out of range (1..{count}); "
            f"use --list-cases to enumerate cases")


def run_case(case_id, bench_only=False, warmup=20, iters=200, case_index=None):
    """运行一个测试 case 组（case_index 非空时只跑组内第 case_index 个），
    返回 (passed, failed, avg_speedup)。

    数值组每例打印明细行并记录 speedup；v5 异常组不计性能（avg 返回 None）。
    """
    passed = failed = 0
    speedups = []

    if case_id == 'v5':
        entries = V5_ENTRIES
        if case_index is not None:
            _check_case_index(case_id, case_index, len(entries))
            entries = [entries[case_index - 1]]
        for kind, val in entries:
            if kind == 'page_size':
                ok = _expects_runtime_error(_build_invalid_ps_kw(val))
                passed, failed = passed + ok, failed + (not ok)
                print(f"  [page_size={val}] "
                      f"{'PASS: raised RuntimeError' if ok else 'FAIL: no RuntimeError'}")
            else:
                ok = _expects_runtime_error(_build_contract_kw(val))
                passed, failed = passed + ok, failed + (not ok)
                print(f"  [{val}] "
                      f"{'PASS: raised RuntimeError' if ok else 'FAIL: no RuntimeError'}")
        return passed, failed, None

    cases, build = _NUMERIC_CASES[case_id]
    if case_index is not None:
        _check_case_index(case_id, case_index, len(cases))
        cases = [cases[case_index - 1]]
    for case in cases:
        try:
            kw = build(case)
        except AssertionError as e:
            failed += 1
            print(f"  [case {case['note']}] FAIL (precondition: {e})")
            continue
        ok, t_tri, t_aiter = _run_numeric_case(kw, case, bench_only,
                                               warmup=warmup, iters=iters)
        extra = _write_traffic_note(kw) if case_id == 'v3' else ''
        if ok:
            passed += 1
            speedup = t_tri / t_aiter if t_aiter > 0 else float('inf')
            speedups.append(speedup)
            bench = (f" | Triton {t_tri:.3f} ms | AITER {t_aiter:.3f} ms | "
                     f"Speedup {speedup:.2f}x") if t_aiter > 0 else ""
            print(f"  [case {case['note']}] PASS{extra}{bench}")
        else:
            failed += 1
            print(f"  [case {case['note']}] FAIL{extra} (correctness mismatch)")

    avg = (sum(speedups) / len(speedups)) if speedups else None
    return passed, failed, avg


@pytest.mark.skipif(not torch.cuda.is_available(), reason="CUDA not available")
def test_benchmark_source_equivalent():
    """Benchmark AITER vs the Triton reference on the default config set.

    与 LightOp 源测试 main() test_configs 逐参数一致（同输入、同计时口径），
    迁移前后性能可直接对比。
    """
    for case in DEFAULT_CASES:
        cfg = {k: case[k] for k in ('B', 'num_reqs', 'max_seq_pages',
                                    'page_size', 'seq_len_delta', 'use_swa')}
        t_triton = benchmark_gpu_events(cfg, run_triton)
        t_aiter = benchmark_gpu_events(cfg, _get_aiter_fn())
        speedup = t_triton / t_aiter if t_aiter > 0 else float('inf')
        print(f"[BASELINE] {case['note']} | Triton {t_triton:.3f} ms | "
              f"AITER {t_aiter:.3f} ms | Speedup: {speedup:.2f}x")


# ---------------------------------------------------------------------------
# CLI 入口：python test_fused_metadata.py [--bench-only] [--case v1 v2:3 ...]
#           [--list-cases]
# 每个 case 组输出独立的 [CASE vx] 汇总表；缺省只运行 default 基线组；
# all = default + v1..v6；--case 支持 组名:序号 语法只运行组内单个配置
# （1-based，见 --list-cases）；任一失败时退出码为 1。
# ---------------------------------------------------------------------------
def _parse_case_token(token):
    """'v2' -> ('v2', None)；'v2:3' -> ('v2', 3)。"""
    group, sep, idx_str = token.partition(':')
    if not sep:
        return group, None
    try:
        index = int(idx_str)
    except ValueError:
        raise SystemExit(f"error: invalid case index in --case {token!r}")
    if index <= 0:
        raise SystemExit(f"error: case index must be 1-based in --case {token!r}")
    return group, index


def _list_cases():
    """打印全部 case 组及其 1-based case 序号（供 --case 组名:N 引用）。"""
    for case_id, desc in _CASE_DESCRIPTIONS.items():
        print(f"[{case_id}] {desc}")
        if case_id == 'v5':
            for i, ps in enumerate(V5_INVALID_PAGE_SIZES, 1):
                print(f"  {i:3d}. page_size={ps}")
            for i, cid in enumerate(V5_CONTRACT_CASES,
                                    len(V5_INVALID_PAGE_SIZES) + 1):
                print(f"  {i:3d}. {cid}")
        else:
            cases, _ = _NUMERIC_CASES[case_id]
            for i, case in enumerate(cases, 1):
                print(f"  {i:3d}. {case['note']}")


def main():
    parser = argparse.ArgumentParser(
        description='Correctness & benchmark tests for aiter.fused_metadata_kernel_general')
    parser.add_argument('--bench-only', action='store_true',
                        help='skip correctness asserts, run benchmarks only')
    parser.add_argument('--warmup', type=int, default=20,
                        help='un-timed warmup calls per benchmark (default: 20)')
    parser.add_argument('--iters', type=int, default=200,
                        help='total timed iterations per benchmark (default: 200)')
    parser.add_argument('--list-cases', action='store_true',
                        help='print all case groups with 1-based case indices, then exit')
    parser.add_argument(
        '--case', nargs='+', default=['default'], metavar='GROUP[:N]',
        help='default: 基线配置集（LightOp 源测试逐参数移植）；'
             'v1-v6: 按测试方向分组的测试集（见 _CASE_DESCRIPTIONS）；'
             'all = default + v1..v6；'
             'GROUP:N 只运行该组第 N 个 case（1-based，见 --list-cases）')
    args = parser.parse_args()

    if args.list_cases:
        _list_cases()
        return

    torch.cuda.set_device(0)
    total_failed = 0

    case_ids = []
    case_indices = {}
    for token in args.case:
        group, index = _parse_case_token(token)
        if group == 'all':
            if index is not None:
                raise SystemExit(
                    "error: --case all:N is ambiguous; select a single group")
            groups = ['default', 'v1', 'v2', 'v3', 'v4', 'v5', 'v6']
        else:
            if group not in _CASE_DESCRIPTIONS:
                raise SystemExit(
                    f"error: unknown case group {group!r} "
                    f"(valid: default, v1..v6, all)")
            groups = [group]
        for g in groups:
            case_ids.append(g)
            if index is not None:
                case_indices[g] = index

    for case_id in case_ids:
        sel = case_indices.get(case_id)
        header = f'{case_id}:{sel}' if sel is not None else case_id
        print('=' * 72)
        print(f'[CASE {header}] {_CASE_DESCRIPTIONS[case_id]}')
        print('=' * 72)
        if args.bench_only and case_id == 'v5':
            # 异常断言组在 --bench-only 下无正确性可跳。
            print('  skipped under --bench-only (exception case)')
            continue
        passed, failed, avg = run_case(case_id, bench_only=args.bench_only,
                                       warmup=args.warmup, iters=args.iters,
                                       case_index=sel)
        if avg is not None:
            print(f"\n[CASE {case_id}] average speedup: {avg:.2f}x   "
                  f"correctness: {passed} passed, {failed} failed")
        else:
            label = 'exceptions' if case_id == 'v5' else 'correctness'
            print(f"\n[CASE {case_id}] {label}: {passed}/{passed + failed} passed")
        total_failed += failed

    if total_failed > 0:
        print(f"\nFAILED: {total_failed} case(s) failed overall")
        sys.exit(1)
    print("\nAll checks passed.")


if __name__ == '__main__':
    main()
