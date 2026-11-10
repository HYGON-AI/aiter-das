# SPDX-License-Identifier: MIT
"""FlashKDA 测试共享输入构造、case 表与小型索引 oracle。

这里是**普通 helper**：不导入任何 `test_*` 模块，也不驱动 GPU。测试与 benchmark
单向导入本模块。

数据契约摘要（与 `aiter/ops/flash_kda.py` 一致）：

* q/k/v/g 为 BF16 ``[B,T,H,128]``，v 的 V 固定 128
* 默认生成 FP32 beta ``[B,T,H]``，内容为 sigmoid **前**的 logits；接口也接受 BF16
* state 为 ``[N,H,K,V]``（最后两维是 key、value），FP32 或 BF16
"""

from __future__ import annotations

import itertools

import torch

C16 = 16
KEY_DIM = 128
VALUE_DIM = 128
SCALE = KEY_DIM ** -0.5
LOWER_BOUND = -5.0

#: 生产验收阈值：out 与 final_state 各一组
#: ``relative_l2 = ‖Δ‖ / (‖ref‖ + 1e-6)``，``max_abs = max|Δ|``
OUT_MAX_ABS = 0.02
OUT_REL_L2 = 0.02
STATE_MAX_ABS = 0.05
STATE_REL_L2 = 0.05

#: workspace 未用槽毒值（bf16/fp16 均可精确表示）
POISON = {
    "kdqd": 1234.0,
    "krgt": -987.0,
    "inv": 321.0,
    "mqk": -654.0,
    "beta_sigmoid": 1234.5,
}


def make_inputs(shape, *, seed, state_dtype, lengths=None):
    """构造一组 FlashKDA 输入，返回键固定。

    ``shape`` 为 ``(B, T, H)``。``lengths=None`` 表示定长；变长必须 ``sum(lengths) == T``
    且物理 ``B == 1``。随机数只使用**局部** generator，不重置全局随机状态。
    """
    B, T, H = (int(x) for x in shape)
    if B <= 0 or H <= 0:
        raise ValueError("B and H must be positive")
    if lengths is None:
        if T <= 0:
            raise ValueError("fixed-length T must be positive")
        n_seqs = B
    else:
        lengths = [int(x) for x in lengths]
        if B != 1:
            raise ValueError("varlen requires physical B=1")
        if not lengths:
            raise ValueError("lengths must not be empty")
        if any(x < 0 for x in lengths):
            raise ValueError("lengths must be non-negative")
        if sum(lengths) != T:
            raise ValueError(f"sum(lengths)={sum(lengths)} must equal T={T}")
        n_seqs = len(lengths)

    gen = torch.Generator(device="cpu").manual_seed(int(seed))
    device = torch.device("cuda")

    def take(shape_, dtype, scale=0.5):
        raw = torch.randn(shape_, generator=gen, dtype=torch.float32) * scale
        return raw.to(device=device, dtype=dtype)

    q = take((B, T, H, KEY_DIM), torch.bfloat16)
    k = take((B, T, H, KEY_DIM), torch.bfloat16)
    v = take((B, T, H, VALUE_DIM), torch.bfloat16)
    g = take((B, T, H, KEY_DIM), torch.bfloat16)
    beta = take((B, T, H), torch.float32)          # sigmoid 之前的 logits
    a_log = take((H,), torch.float32)
    dt_bias = take((H, KEY_DIM), torch.float32)    # 文档首选 [H,K]
    # state 取小值随机数：天然非对称，K/V 轴顺序写错会立刻在数值上暴露。
    state = (torch.randn((n_seqs, H, KEY_DIM, VALUE_DIM), generator=gen,
                         dtype=torch.float32) * 0.01).to(device=device,
                                                         dtype=state_dtype)

    cu_seqlens = None
    if lengths is not None:
        cu = torch.tensor([0] + list(itertools.accumulate(lengths)),
                          dtype=torch.int64, device=device)
        cu_seqlens = cu

    return {
        "q": q,
        "k": k,
        "v": v,
        "g": g,
        "beta": beta,
        "A_log": a_log,
        "dt_bias": dt_bias,
        "state": state,
        "cu_seqlens": cu_seqlens,
    }


# ---------------------------------------------------------------------------
# 公共数值 case 表（ID 与执行计划 B3 一致）
# ---------------------------------------------------------------------------

#: 定长：``(id, (B,T,H), state_dtype)``
FIXED_CASES = [
    ("F01", (1, 1, 6), torch.float32),      # 单 token
    ("F02", (1, 16, 6), torch.float32),     # 整 chunk
    ("F03", (2, 33, 6), torch.float32),     # B>1 与尾块
    ("F04", (1, 65, 6), torch.bfloat16),    # BF16 终态、尾块
    ("F05", (1, 129, 6), torch.bfloat16),   # 尾块
    ("F06", (1, 1024, 96), torch.float32),  # 高 H plain
    ("F07", (1, 8192, 6), torch.float32),   # 自动分段
]

#: 变长：``(id, lengths, H, state_dtype)``
VARLEN_CASES = [
    ("V01", [33], 6, torch.float32),                                # 单序列 packed
    ("V02", [10, 20, 30, 500, 1000, 2001], 6, torch.float32),        # 多序列多尾块
    ("V03", [1300, 547, 2048, 963, 271, 3063], 96, torch.float32),   # 高 H 多序列
    ("V04", [10, 0, 30, 500, 1000, 2001], 6, torch.float32),         # 空序列初态保持
    ("V05", [0, 0, 0], 6, torch.float32),                            # T=0 全空
]

#: V06：同总长 T(33) 的两种分区，cu 内容不得被缓存
V06_PARTITIONS = [[17, 16], [1, 32]]
V06_HEADS = 6

#: F08：与 F07 同输入，强制 plain
F08_SHAPE = (1, 8192, 6)


def fixed_case_params(only=None):
    """把 ``FIXED_CASES`` 转成 pytest 参数化的 ``(id, shape, state_dtype)``。"""
    return [case for case in FIXED_CASES if only is None or case[0] in only]


def varlen_case_params(only=None):
    """把 ``VARLEN_CASES`` 转成 pytest 参数化的 ``(id, lengths, H, state_dtype)``。"""
    return [case for case in VARLEN_CASES if only is None or case[0] in only]


def case_seed(case_id):
    """case id → 稳定的局部 seed（不依赖全局随机状态）。"""
    total = 0
    for ch in str(case_id):
        total = (total * 131 + ord(ch)) % 100000
    return 20261028 + total % 1000


# ---------------------------------------------------------------------------
# 小型索引 oracle（纯 Python，不 import torch、不初始化设备）
# ---------------------------------------------------------------------------
def chunk_counts(lengths):
    """每序列的 chunk 数 ``ceil(L/16)``；空序列为 0。"""
    return [(int(length) + C16 - 1) // C16 for length in lengths]


def prefix_offsets(counts):
    """chunk 前缀和，长度 ``N+1``。"""
    offsets = [0]
    for count in counts:
        offsets.append(offsets[-1] + int(count))
    return offsets


def sequence_info_from(lengths):
    """CPU 侧独立构造 ``sequence_info`` 三列：``bos / L / chunk0``。"""
    rows = []
    bos = 0
    chunk0 = 0
    for length, count in zip(lengths, chunk_counts(lengths)):
        rows.append([bos, int(length), chunk0])
        bos += int(length)
        chunk0 += int(count)
    return rows


def qcap_for(lengths, qcap_extra):
    """每个 head 的 chunk 槽容量；``qcap_extra < 0`` 用生产者上界 ``ceil(T/16)+N``。"""
    lengths = list(lengths)
    total = sum(lengths)
    used = sum(chunk_counts(lengths))
    if qcap_extra < 0:
        return max(1, (total + C16 - 1) // C16 + len(lengths))
    return max(1, used + int(qcap_extra))


def p_index(head, qcap, chunk0, local_chunk):
    """head-major 槽下标：head stride 是 **Qcap**，不是实际使用 chunk 数。"""
    return int(head) * int(qcap) + int(chunk0) + int(local_chunk)


def slot_owners(lengths, heads, qcap):
    """返回 ``(head, slot)`` 的归属 ``(seq, local_chunk)`` 或 ``None``（未用槽）。"""
    rows = sequence_info_from(lengths)
    counts = chunk_counts(lengths)
    owners = []
    for head in range(int(heads)):
        for slot in range(int(qcap)):
            owner = None
            for seq, (_, length, chunk0) in enumerate(rows):
                if counts[seq] and chunk0 <= slot < chunk0 + counts[seq]:
                    owner = (seq, slot - chunk0)
                    break
            owners.append(((head, slot), owner))
    return owners


def unused_p(lengths, heads, qcap):
    """未用槽的 ``p`` 下标列表（用于毒值/哨兵断言）。"""
    out = []
    for (head, slot), owner in slot_owners(lengths, heads, qcap):
        if owner is not None:
            continue
        out.append(p_index(head, qcap, 0, slot))
    return out


def used_p(lengths, heads, qcap):
    """已用槽的 ``p`` 下标列表。"""
    rows = sequence_info_from(lengths)
    out = []
    for (head, slot), owner in slot_owners(lengths, heads, qcap):
        if owner is None:
            continue
        seq, local = owner
        out.append(p_index(head, qcap, rows[seq][2], local))
    return out
