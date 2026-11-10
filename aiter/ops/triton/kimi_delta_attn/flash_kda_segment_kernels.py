# SPDX-License-Identifier: MIT
#
# FlashKDA 的段间 Triton kernel：分段 replay、段间 scan 与 K2 autotune 分桶。

import torch
import triton
import triton.language as tl

from .chunk_delta_attn_utils import (
    CHUNK_DELTA_ATTN_TRITON_AUTOTUNE,
    autotune_cache_kwargs,
    chunk_delta_attn_autotune_configs,
    exp,
    exp2,
    input_guard,
    tensor_cache,
)

_K2_CONFIGS: list = (
    [
        triton.Config({"BW": BW}, num_warps=nw, num_stages=ns)
        for BW in [16, 32, 64]
        for nw in [2, 4]
        for ns in [1, 2]
    ]
    if CHUNK_DELTA_ATTN_TRITON_AUTOTUNE
    else [
        triton.Config({"BW": 16}, num_warps=2, num_stages=2),
        triton.Config({"BW": 32}, num_warps=2, num_stages=2),
        triton.Config({"BW": 64}, num_warps=4, num_stages=2),
    ]
)

def _seg_occupancy_class(num_segs: int) -> int:
    """为 K2 的 autotune key 对 ``num_segs`` 分桶。

    网格大小为 ``cdiv(W, BW) * num_segs * H``，因此最佳 BW 随 segment 数量变化：segment
    很少时大 BW 的 block 数会掉到四分之一。精确数量作 key 会让每个 batch 重新调优，
    二的幂次分桶已足以区分调度方式。
    """
    return max(1, num_segs).bit_length()


@triton.autotune(
    configs=_K2_CONFIGS,
    # HAS_V / COMPUTE_OUTPUT 被放入 key，是因为下面三个阶段每次迭代的开销差异很大，不能共享调优配置；
    # NUM_SEGS_CLASS 也是同样的原因——没有它时，分段和不分段的调度会发生冲突，先运行的那一种会为两者设置配置，
    # 之后磁盘缓存还会保留这个结果。
    key=["H", "K", "W", "C", "HAS_V", "COMPUTE_OUTPUT", "NUM_SEGS_CLASS"],
    **autotune_cache_kwargs,
)
@triton.jit
def _flash_kda_segment_kernel(
    ws_kd,
    ws_qd,
    ws_kr,
    ws_gt,
    ws_inv_mqk,
    v_input,
    beta_raw,
    out,
    h_in,
    h_out,
    final_state,
    seg_chunk_base,
    seg_nchunks,
    seg_tok_base,
    seg_tok_end,
    seg_seq,
    seg_is_last,
    TOTAL_TILES,
    NUM_SEGS_CLASS,  # tuning discriminator only; see _seg_occupancy_class
    H: tl.constexpr,
    K: tl.constexpr,
    V: tl.constexpr,
    W: tl.constexpr,
    C: tl.constexpr,
    BW: tl.constexpr,
    INIT_IDENTITY: tl.constexpr,
    HAS_H_IN: tl.constexpr,
    HAS_V: tl.constexpr,
    COMPUTE_OUTPUT: tl.constexpr,
    STORE_H_OUT: tl.constexpr,
    STORE_FINAL: tl.constexpr,
    STATE_V_FIRST: tl.constexpr,
):
    """对一个 chunk segment 执行 delta 规则递推。

    状态更新关于输入状态是仿射的，即 ``h' = A_seg h + b_seg``。因此，通过改变初始状态和存储内容，同一个内核可以服务于分段（context parallel）调度的三个阶段：

      * ``h=0``、真实 ``v``            -> ``b_seg``  （仿射部分）
      * ``h=I``、``v=0``（``W = K``）   -> ``A_seg``  （线性部分；每个 program 对应一个列块，
        通过传播基而不是展开每个 chunk 的算子乘积来得到该算子）
      * 扫描得到的 ``h=h_in``、真实 ``v``、``COMPUTE_OUTPUT`` -> 输出

    当每个序列只有一个 segment 时，它会退化为普通的顺序扫描，只执行第三种形式。
    """
    i_w = tl.program_id(0).to(tl.int64)
    i_sh = tl.program_id(1).to(tl.int64)
    i_seg, i_h = i_sh // H, i_sh % H

    chunk_base = tl.load(seg_chunk_base + i_seg).to(tl.int64)
    n_chunks = tl.load(seg_nchunks + i_seg)
    tok_base = tl.load(seg_tok_base + i_seg).to(tl.int64)
    tok_end = tl.load(seg_tok_end + i_seg).to(tl.int64)

    o_c = tl.arange(0, C)
    o_k1 = tl.arange(0, 64)
    o_k2 = 64 + tl.arange(0, 64)
    o_w = i_w * BW + tl.arange(0, BW)
    m_w = o_w < W

    # 状态布局为 [K, W]；K 被拆成两个各含 64 行的部分，使每个 tile 成为一个 [64, BW] 的 fp32 寄存器块。
    if INIT_IDENTITY:
        b_h1 = tl.where(o_k1[:, None] == o_w[None, :], 1.0, 0.0)
        b_h2 = tl.where(o_k2[:, None] == o_w[None, :], 1.0, 0.0)
    elif HAS_H_IN:
        s_off = (i_seg * H + i_h) * K * W + o_w[None, :]
        b_h1 = tl.load(h_in + s_off + o_k1[:, None] * W, mask=m_w[None, :], other=0.0)
        b_h2 = tl.load(h_in + s_off + o_k2[:, None] * W, mask=m_w[None, :], other=0.0)
        b_h1 = b_h1.to(tl.float32)
        b_h2 = b_h2.to(tl.float32)
    else:
        b_h1 = tl.zeros([64, BW], dtype=tl.float32)
        b_h2 = tl.zeros([64, BW], dtype=tl.float32)

    for j in range(n_chunks):
        ws_idx = i_h * TOTAL_TILES + chunk_base + j
        ck = ws_idx * C * K
        t0 = tok_base + j * C
        m_c = (t0 + o_c) < tok_end
        m_cw = m_c[:, None] & m_w[None, :]

        b_h1_bf = b_h1.to(tl.bfloat16)
        b_h2_bf = b_h2.to(tl.bfloat16)

        b_kd1 = tl.load(ws_kd + ck + o_c[:, None] * K + o_k1[None, :])
        b_kd2 = tl.load(ws_kd + ck + o_c[:, None] * K + o_k2[None, :])
        b_tmp = tl.dot(b_kd1, b_h1_bf) + tl.dot(b_kd2, b_h2_bf)

        vo_off = t0 * H * V + i_h * V + o_c[:, None] * (H * V) + o_w[None, :]
        if HAS_V:
            b_v = tl.load(v_input + vo_off, mask=m_cw, other=0.0).to(tl.float32)
        else:
            b_v = tl.zeros([C, BW], dtype=tl.float32)

        p_beta = beta_raw + t0 * H + i_h + o_c * H
        b_beta = tl.sigmoid(tl.load(p_beta, mask=m_c, other=0.0).to(tl.float32))

        # 尾部行必须保持为 0：U 会参与状态更新，而状态更新会累加全部 C 行，不论其中有多少是真实行。
        b_u = tl.where(m_c[:, None], (b_v - b_tmp) * b_beta[:, None], 0.0)

        cc = ws_idx * 2 * C * C + o_c[:, None] * C + o_c[None, :]
        b_inv = tl.load(ws_inv_mqk + cc)
        b_U = tl.dot(b_inv, b_u.to(ws_inv_mqk.dtype.element_ty))

        if COMPUTE_OUTPUT:
            b_mqk = tl.load(ws_inv_mqk + cc + C * C)
            b_qd1 = tl.load(ws_qd + ck + o_c[:, None] * K + o_k1[None, :])
            b_qd2 = tl.load(ws_qd + ck + o_c[:, None] * K + o_k2[None, :])
            b_o = tl.dot(b_qd1, b_h1_bf) + tl.dot(b_qd2, b_h2_bf)
            b_o += tl.dot(b_mqk, b_U.to(b_mqk.dtype))
            tl.store(out + vo_off, b_o.to(out.dtype.element_ty), mask=m_cw)

        b_gt1 = tl.load(ws_gt + ws_idx * K + o_k1).to(tl.float32)
        b_gt2 = tl.load(ws_gt + ws_idx * K + o_k2).to(tl.float32)

        # 递推本身的矩阵乘法保持使用 bf16：将其扩宽会增加约 40% 的内核开销，却没有可测量地改善误差上界，
        # 因为它们输入的状态无论如何都会在 fp32 中累加，而 U 已经携带了上面求逆过程中损失的精度。
        b_U_bf = b_U.to(tl.bfloat16)
        b_kr1_t = tl.load(ws_kr + ck + o_k1[:, None] + o_c[None, :] * K)
        b_kr2_t = tl.load(ws_kr + ck + o_k2[:, None] + o_c[None, :] * K)

        b_h1 = b_h1 * b_gt1[:, None] + tl.dot(b_kr1_t, b_U_bf).to(tl.float32)
        b_h2 = b_h2 * b_gt2[:, None] + tl.dot(b_kr2_t, b_U_bf).to(tl.float32)

    if STORE_H_OUT:
        s_off = (i_seg * H + i_h) * K * W + o_w[None, :]
        e_ty = h_out.dtype.element_ty
        tl.store(h_out + s_off + o_k1[:, None] * W, b_h1.to(e_ty), mask=m_w[None, :])
        tl.store(h_out + s_off + o_k2[:, None] * W, b_h2.to(e_ty), mask=m_w[None, :])

    # 不将两个条件合并：外层判断是 constexpr；当它为 false 时，final_state 是空指针，不能读取 seg_is_last。
    if STORE_FINAL:  # noqa: SIM102
        if tl.load(seg_is_last + i_seg) == 1:
            i_n = tl.load(seg_seq + i_seg).to(tl.int64)
            if STATE_V_FIRST:
                f_off = (i_n * H + i_h) * V * K + o_w[None, :] * K
                tl.store(final_state + f_off + o_k1[:, None], b_h1, mask=m_w[None, :])
                tl.store(final_state + f_off + o_k2[:, None], b_h2, mask=m_w[None, :])
            else:
                f_off = (i_n * H + i_h) * K * V + o_w[None, :]
                tl.store(
                    final_state + f_off + o_k1[:, None] * V, b_h1, mask=m_w[None, :]
                )
                tl.store(
                    final_state + f_off + o_k2[:, None] * V, b_h2, mask=m_w[None, :]
                )


@triton.heuristics({"HAS_H0": lambda args: args["h0"] is not None})
@triton.jit
def _flash_kda_seg_scan_kernel(
    A_seg,
    b_seg,
    h_in,
    h0,
    seq_seg_off,
    H: tl.constexpr,
    K: tl.constexpr,
    V: tl.constexpr,
    BV: tl.constexpr,
    HAS_H0: tl.constexpr,
):
    """跨序列中的 segment 执行串行扫描：``h <- A_seg h + b_seg``。

    它每个 segment 只运行一次，而不是每个 chunk 运行一次，因此串行深度是 segment 数量（通常为个位数），而不是 chunk 数量。
    """
    i_v = tl.program_id(0).to(tl.int64)
    i_nh = tl.program_id(1).to(tl.int64)
    i_n, i_h = i_nh // H, i_nh % H

    s0 = tl.load(seq_seg_off + i_n).to(tl.int64)
    s1 = tl.load(seq_seg_off + i_n + 1).to(tl.int64)

    o_k1 = tl.arange(0, 64)
    o_k2 = 64 + tl.arange(0, 64)
    o_v = i_v * BV + tl.arange(0, BV)
    m_v = o_v < V

    if HAS_H0:
        base = (i_n * H + i_h) * K * V + o_v[None, :]
        b_h1 = tl.load(h0 + base + o_k1[:, None] * V, mask=m_v[None, :], other=0.0)
        b_h2 = tl.load(h0 + base + o_k2[:, None] * V, mask=m_v[None, :], other=0.0)
    else:
        b_h1 = tl.zeros([64, BV], dtype=tl.float32)
        b_h2 = tl.zeros([64, BV], dtype=tl.float32)

    for s in range(s0, s1):
        hb = (s * H + i_h) * K * V + o_v[None, :]
        tl.store(h_in + hb + o_k1[:, None] * V, b_h1, mask=m_v[None, :])
        tl.store(h_in + hb + o_k2[:, None] * V, b_h2, mask=m_v[None, :])

        # A_seg 以 bf16 存储：下面的 dot 无论如何都会将它作为 bf16 使用；在当前 block 数下，
        # 扫描速度受读取算子的速度限制，而不是受算术计算限制。
        ab = (s * H + i_h) * K * K
        b_A11 = tl.load(A_seg + ab + o_k1[:, None] * K + o_k1[None, :])
        b_A12 = tl.load(A_seg + ab + o_k1[:, None] * K + o_k2[None, :])
        b_A21 = tl.load(A_seg + ab + o_k2[:, None] * K + o_k1[None, :])
        b_A22 = tl.load(A_seg + ab + o_k2[:, None] * K + o_k2[None, :])

        b_h1_bf = b_h1.to(tl.bfloat16)
        b_h2_bf = b_h2.to(tl.bfloat16)
        b_n1 = tl.dot(b_A11, b_h1_bf) + tl.dot(b_A12, b_h2_bf)
        b_n2 = tl.dot(b_A21, b_h1_bf) + tl.dot(b_A22, b_h2_bf)

        b_h1 = b_n1 + tl.load(
            b_seg + hb + o_k1[:, None] * V, mask=m_v[None, :], other=0.0
        )
        b_h2 = b_n2 + tl.load(
            b_seg + hb + o_k2[:, None] * V, mask=m_v[None, :], other=0.0
        )

