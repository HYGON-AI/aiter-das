// SPDX-License-Identifier: MIT
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.
//
// PassA：逐段计算 affine 转换的 A（transition）与 b（update）两半。

#ifndef FLASH_KDA_SEGMENT_PASS_CUH
#define FLASH_KDA_SEGMENT_PASS_CUH

#include "flash_kda_segment_common.cuh"

// ---------------------------------------------------------------------------
// PassA：四 wave、双状态。每组 chunk 的 MMAC 组成
//   M1 = 16 BF16（kh0 = kd·update_state^T、kh1 = kd·transition_state^T，kd 只读一次）
//   M2 = 2 FP16（U0 = u0·inv^T、U1 = u1·inv^T）
//   M3 = 16 BF16（update0/1 = U0/1·kr^T，kr 只读一次）
// 本 pass 不读 qd/mqk、不写逐 token out。
// LDS：kd 双槽 8 KiB + kr|gt 单共享槽 4608 B = 12736 B。
// 出口写 segment_update（FP32，逻辑 K 行）与 segment_transition（BF16，AsegPerm 物理写行）。
__global__ __launch_bounds__(seg4w::kWaves * 64) void kda_passA_c16_4w(
    const unsigned short *ws_kdqd, // kd 半区（PassA 不读 qd）
    const unsigned short *ws_krgt, // kr|gt 合并区
    const unsigned short *ws_inv,
    const unsigned short *v,
    const float *beta_sigmoid,
    float *segment_update,
    unsigned short *segment_transition,
    int sequence_count,
    int heads,
    int input_token_count,
    int workspace_head_stride_chunks,
    int segment_count,
    int chunks_per_segment)
{
    const int tid = static_cast<int>(threadIdx.x);
    const int lane = tid & 63;
    const int wave = tid >> 6;
    const int row = lane & 15;
    const int group = lane >> 4;
    const int value_group = static_cast<int>(blockIdx.x) * seg4w::kWaves + wave;
    const int bh_count = sequence_count * heads;
    const int block_y = static_cast<int>(blockIdx.y);
    const int segment = block_y / bh_count;
    const int bh = block_y % bh_count;
    if (segment >= segment_count || bh >= bh_count || value_group >= kValueDim / 16)
        return;

    const int b = bh / heads;
    const int head = bh % heads;
    const int chunk_count = (input_token_count + kChunkSize - 1) / kChunkSize;
    const int chunk_begin = segment * chunks_per_segment;
    const int chunk_end = min(chunk_count, chunk_begin + chunks_per_segment);
    const int col0 = value_group * 16;
    const int vcol = col0 + row;

    __shared__ __align__(16) unsigned short s_kd[2 * seg4w::kKdqdTileU16];
    __shared__ __align__(16) unsigned short s_krgt[kKrgtStrideU16];

    // ===== 双状态初始化（B-fragment）：update_state = 0；transition_state = 单位矩阵 =====
    float update_state[kKeyDim / 16][4] = {};
    float transition_state[kKeyDim / 16][4];
#pragma unroll
    for (int kk = 0; kk < kKeyDim / 16; ++kk)
#pragma unroll
        for (int s = 0; s < 4; ++s)
            transition_state[kk][s] = (kk * 16 + 4 * group + s == col0 + row) ? 1.0f : 0.0f;

    // ===== 序言：本段首 chunk 的 kd → 槽 0；kr|gt → 单共享槽 =====
    int64_t workspace_chunk_index = static_cast<int64_t>(head) * workspace_head_stride_chunks +
                                    static_cast<int64_t>(b) * chunk_count + chunk_begin;
    seg4w::issue_kdqd<false>(tid, workspace_chunk_index, ws_kdqd, nullptr, s_kd, nullptr);
    seg4w::issue_krgt(tid, workspace_chunk_index, ws_krgt, s_krgt);

    int stage = 0;
#pragma unroll 1
    for (int chunk = chunk_begin; chunk < chunk_end; ++chunk, workspace_chunk_index += 1)
    {
        const bool is_first = (chunk == chunk_begin);
        const bool has_next = (chunk + 1 < chunk_end);
        const int token_base = chunk * kChunkSize;
        const unsigned short *const kd_cur = s_kd + stage * seg4w::kKdqdTileU16;

        // ===== (0) 顶部：等本代 kd 直写落地（VM 门控；ds_read 之前）=====
        // 序言/稳态在飞都是 kd1 + krgt2 = 3（PassA 没有 out store 垫底）
        // ⇒ vmcnt(2) 恰好退掉最老的 kd，保留 krgt 到下面的 B 发布点。
        kda_c16_asm::wait_vmcnt_only<2>();
        kda_c16_asm::sched_pin();
        asm volatile("s_barrier" ::: "memory"); // A：跨 wave 发布 kd
        kda_c16_asm::sched_pin();

        // ===== 本代 V / beta / inv（全局，VM 记账：4 + 4 + 1 = 9）=====
        unsigned int v_raw[4];
        {
            const seg4w::vec4_u32 rsrc_v = seg4w::make_rsrc(v);
            const unsigned int v_soff = static_cast<unsigned int>(
                ((static_cast<int64_t>(b) * input_token_count + token_base) * heads + head) * kValueDim * 2);
#pragma unroll
            for (int s = 0; s < 4; ++s)
            {
                const int token_s = token_base + group + 4 * s;
                const int token_rel =
                    (token_s < input_token_count) ? (group + 4 * s) : (input_token_count - 1 - token_base);
                kda_c16_asm::buffer_load_ushort(
                    v_raw[s], rsrc_v, v_soff, (token_rel * heads * kValueDim + vcol) * 2);
            }
        }

        // ===== (1) 本代 kd 的 ds_read（8 条 b64；没有 qd）=====
        unsigned long long rk[8];
        {
            const unsigned int kd_lane = kda_c16_asm::lds_byte_addr(
                kd_cur, static_cast<unsigned int>(kda_c16_kdqd_seg_cons_u16(row, group) * 2));
#pragma unroll
            for (int kt = 0; kt < kKeyDim / 16; ++kt)
                kda_c16_asm::ds_read_b64(kd_lane + static_cast<unsigned int>(kt) * 512u, rk[kt]);
        }

        float beta_reg[4];
        unsigned long long inv_reg;
        {
            const seg4w::vec4_u32 rsrc_beta =
                seg4w::make_rsrc(beta_sigmoid + workspace_chunk_index * kChunkSize);
            const seg4w::vec4_u32 rsrc_inv =
                seg4w::make_rsrc(ws_inv + workspace_chunk_index * kChunkSize * kChunkSize);
            const int packed_voff = (row * 4 + group) * 8;
#pragma unroll
            for (int s = 0; s < 4; ++s)
                kda_c16_asm::buffer_load_dwordx1(beta_reg[s], rsrc_beta, 0u,
                                                 (group + 4 * s) * 4);
            kda_c16_asm::buffer_load_dwordx2(inv_reg, rsrc_inv, 0u, packed_voff);
        }

        // ===== (3) 下一代 kd（只有 kd；PassA 不读 qd）=====
        if (has_next)
            seg4w::issue_kdqd<false>(tid, workspace_chunk_index + 1, ws_kdqd, nullptr,
                                     s_kd + (stage ^ 1) * seg4w::kKdqdTileU16, nullptr);

        kda_c16_asm::wait_lgkmcnt_only<0>();

        // ===== 第一组 MMAC：kh0/kh1（kd 一次读服务两条状态链）=====
        vec4_fp32 kh0{0, 0, 0, 0};
        vec4_fp32 kh1{0, 0, 0, 0};
#pragma unroll
        for (int kt = 0; kt < kKeyDim / 16; ++kt)
        {
            const auto a_k = __builtin_bit_cast(flash_kda_k2_fragments::vec4_bf16, rk[kt]);
            flash_kda_k2_fragments::vec4_bf16 b0{};
            flash_kda_k2_fragments::vec4_bf16 b1{};
#pragma unroll
            for (int s = 0; s < 4; ++s)
            {
                b0[s] = flash_kda_k2_fragments::float_to_bf16_rne_fast(update_state[kt][s]);
                b1[s] = flash_kda_k2_fragments::float_to_bf16_rne_fast(transition_state[kt][s]);
            }
            kda_c16_asm::mmac_bf16(kh0, b0, a_k);
            kda_c16_asm::mmac_bf16(kh1, b1, a_k);
        }

        // ===== 收口本代 kr|gt 搬运再发布 =====
        // 在飞（老→新）= krgt2 + beta4/v4/inv1 + kd(c+1)1 = 12（有 next）/ 11（无 next）
        // ⇒ 10 / 9 退掉最老 2 条（krgt），krgt(c) 落地。
        kda_c16_asm::sched_pin();
        if (has_next)
            kda_c16_asm::wait_vmcnt_only<10>();
        else
            kda_c16_asm::wait_vmcnt_only<9>();
        kda_c16_asm::sched_pin();
        asm volatile("s_barrier" ::: "memory"); // B：跨 wave 发布 kr|gt
        kda_c16_asm::sched_pin();

        vec4_fp32 gt_reg[8];
        unsigned long long kr_reg[8];
        const unsigned int gt_base = kda_c16_asm::lds_byte_addr(s_krgt + kDecayOffsetU16, 0u);
        const unsigned int kr_base = kda_c16_asm::lds_byte_addr(
            s_krgt, static_cast<unsigned int>(flash_kda_k2_fragments::kr_voff(flash_kda_state_layout::natural_kr_row(row), group)));
#pragma unroll
        for (int i = 0; i < 4; ++i)
            kda_c16_asm::ds_read_b128(gt_base + static_cast<unsigned int>(i * 16 + group * 4) * 4u,
                                      gt_reg[i]);
#pragma unroll
        for (int tile = 0; tile < 4; ++tile)
            kda_c16_asm::ds_read_b64(kr_base + static_cast<unsigned int>(tile) * 512u,
                                     kr_reg[tile]);

        // ===== 首次消费 beta/v/inv 前：退掉更早的 9 条 =====
        // 在飞 = 9 + kd(c+1)1 = 10 ⇒ 1 留 1（无 next 时 9 ⇒ 0）。
        kda_c16_asm::sched_pin();
        if (has_next)
            kda_c16_asm::wait_vmcnt_only<1>();
        else
            kda_c16_asm::wait_vmcnt_only<0>();
        kda_c16_asm::ready8<1, 15>(beta_reg[0], beta_reg[1], beta_reg[2], beta_reg[3],
                                   v_raw[0], v_raw[1], v_raw[2], v_raw[3]);
        kda_c16_asm::sched_pin();

        // ===== 第二组：u0/u1 → U0/U1 =====
        float u0[4];
        float u1[4];
#pragma unroll
        for (int s = 0; s < 4; ++s)
        {
            const int token_s = token_base + group + 4 * s;
            const bool valid_s = token_s < input_token_count;
            const float value =
                valid_s ? bf16_to_float(static_cast<unsigned short>(v_raw[s] & 0xffffu)) : 0.0f;
            const float gate = valid_s ? beta_reg[s] : 0.0f;
            u0[s] = (value - kh0[s]) * gate;
            u1[s] = (0.0f - kh1[s]) * gate;
        }
        flash_kda_k2_fragments::vec4_bf16 a_u0{};
        flash_kda_k2_fragments::vec4_bf16 a_u1{};
#pragma unroll
        for (int s = 0; s < 4; ++s)
        {
            a_u0[s] = float_to_bf16(u0[s]);
            a_u1[s] = float_to_bf16(u1[s]);
        }
        const auto a_inv = __builtin_bit_cast(flash_kda_k2_fragments::vec4_bf16, inv_reg);
        vec4_fp32 U0_acc{0, 0, 0, 0};
        vec4_fp32 U1_acc{0, 0, 0, 0};
        kda_c16_asm::mmac_bf16(U0_acc, a_u0, a_inv);
        kda_c16_asm::mmac_bf16(U1_acc, a_u1, a_inv);
        unsigned short U0_bf[4];
        unsigned short U1_bf[4];
#pragma unroll
        for (int s = 0; s < 4; ++s)
        {
            U0_bf[s] = flash_kda_k2_fragments::float_to_bf16_rne_fast(U0_acc[s]);
            U1_bf[s] = flash_kda_k2_fragments::float_to_bf16_rne_fast(U1_acc[s]);
        }
        flash_kda_k2_fragments::vec4_bf16 a_U0_bf{};
        flash_kda_k2_fragments::vec4_bf16 a_U1_bf{};
#pragma unroll
        for (int s = 0; s < 4; ++s)
        {
            a_U0_bf[s] = U0_bf[s];
            a_U1_bf[s] = U1_bf[s];
        }

        // ===== 分批取 gt/kr 的 B 半（pair 2-3）=====
        kda_c16_asm::sched_pin();
#pragma unroll
        for (int i = 4; i < 8; ++i)
            kda_c16_asm::ds_read_b128(gt_base + static_cast<unsigned int>(i * 16 + group * 4) * 4u,
                                      gt_reg[i]);
#pragma unroll
        for (int tile = 4; tile < 8; ++tile)
            kda_c16_asm::ds_read_b64(kr_base + static_cast<unsigned int>(tile) * 512u,
                                     kr_reg[tile]);

        // ===== 分级 LGKM 阶梯：先做 pair 0-1（两条状态链各两条 MMAC）=====
        kda_c16_asm::wait_lgkmcnt_only<8>();
        kda_c16_asm::sched_pin();
#pragma unroll
        for (int pair = 0; pair < 2; ++pair)
        {
            const auto a_kr0 =
                __builtin_bit_cast(flash_kda_k2_fragments::vec4_bf16, kr_reg[pair * 2]);
            const auto a_kr1 =
                __builtin_bit_cast(flash_kda_k2_fragments::vec4_bf16, kr_reg[pair * 2 + 1]);
            vec4_fp32 update00{0, 0, 0, 0};
            vec4_fp32 update01{0, 0, 0, 0};
            vec4_fp32 update10{0, 0, 0, 0};
            vec4_fp32 update11{0, 0, 0, 0};
            kda_c16_asm::mmac_bf16(update00, a_U0_bf, a_kr0);
            kda_c16_asm::mmac_bf16(update01, a_U0_bf, a_kr1);
            kda_c16_asm::mmac_bf16(update10, a_U1_bf, a_kr0);
            kda_c16_asm::mmac_bf16(update11, a_U1_bf, a_kr1);
            const vec4_fp32 &d0 = gt_reg[pair * 2];
            const vec4_fp32 &d1 = gt_reg[pair * 2 + 1];
#pragma unroll
            for (int s = 0; s < 4; ++s)
            {
                update_state[pair * 2][s] = d0[s] * update_state[pair * 2][s] + update00[s];
                update_state[pair * 2 + 1][s] = d1[s] * update_state[pair * 2 + 1][s] + update01[s];
                transition_state[pair * 2][s] = d0[s] * transition_state[pair * 2][s] + update10[s];
                transition_state[pair * 2 + 1][s] = d1[s] * transition_state[pair * 2 + 1][s] + update11[s];
            }
        }
        kda_c16_asm::wait_lgkmcnt_only<0>();
        kda_c16_asm::sched_pin();
#pragma unroll
        for (int pair = 2; pair < kKeyDim / 32; ++pair)
        {
            const auto a_kr0 =
                __builtin_bit_cast(flash_kda_k2_fragments::vec4_bf16, kr_reg[pair * 2]);
            const auto a_kr1 =
                __builtin_bit_cast(flash_kda_k2_fragments::vec4_bf16, kr_reg[pair * 2 + 1]);
            const vec4_fp32 update00 = flash_kda_k2_fragments::opus_mmac_bf16(
                a_U0_bf, a_kr0, vec4_fp32{0, 0, 0, 0});
            const vec4_fp32 update01 = flash_kda_k2_fragments::opus_mmac_bf16(
                a_U0_bf, a_kr1, vec4_fp32{0, 0, 0, 0});
            const vec4_fp32 update10 = flash_kda_k2_fragments::opus_mmac_bf16(
                a_U1_bf, a_kr0, vec4_fp32{0, 0, 0, 0});
            const vec4_fp32 update11 = flash_kda_k2_fragments::opus_mmac_bf16(
                a_U1_bf, a_kr1, vec4_fp32{0, 0, 0, 0});
            const vec4_fp32 &d0 = gt_reg[pair * 2];
            const vec4_fp32 &d1 = gt_reg[pair * 2 + 1];
#pragma unroll
            for (int s = 0; s < 4; ++s)
            {
                update_state[pair * 2][s] = d0[s] * update_state[pair * 2][s] + update00[s];
                update_state[pair * 2 + 1][s] = d1[s] * update_state[pair * 2 + 1][s] + update01[s];
                transition_state[pair * 2][s] = d0[s] * transition_state[pair * 2][s] + update10[s];
                transition_state[pair * 2 + 1][s] = d1[s] * transition_state[pair * 2 + 1][s] + update11[s];
            }
        }

        // ===== 单共享槽覆盖前：本代 kr/gt 读必须完成（WAR）=====
        kda_c16_asm::wait_lgkmcnt_only<0>();
        kda_c16_asm::sched_pin();
        asm volatile("s_barrier" ::: "memory"); // C
        kda_c16_asm::sched_pin();
        if (has_next)
            seg4w::issue_krgt(tid, workspace_chunk_index + 1, ws_krgt, s_krgt);

        stage ^= 1;
    }

    // ===== 段出口：segment_update = update_state（FP32，逻辑 K 行）；segment_transition = BF16(transition_state)（AsegPerm 写行）=====
    // 内部槽位的逻辑 K 是 kk*16 + 4*group + s。
    // segment_update：k_row = 逻辑 K、v_col = col0 + row
    //   soff = ((kk*16 + s)*kValueDim + col0)*4（wave 均匀）
    //   voff = (4*group*kValueDim + row)*4（per-lane）
    // segment_transition（AsegPerm）：写行 = tile_permute(逻辑 K) = kk*16 + group + 4*s
    //   soff = ((kk*16 + 4*s)*kValueDim + col0)*2、voff = (group*kValueDim + row)*2
    // 保持 scan 的中间契约不变 ⇒ 这里必须按上式的物理行写，不能沿用旧写行。
    {
        const int64_t state_base = (static_cast<int64_t>(segment) * bh_count + bh) * kKeyDim * kValueDim;
        const seg4w::vec4_u32 rsrc_b = seg4w::make_rsrc(segment_update + state_base);
        const seg4w::vec4_u32 rsrc_a = seg4w::make_rsrc(segment_transition + state_base);
        const unsigned int voff_b = static_cast<unsigned int>((4 * group * kValueDim + row) * 4);
        const unsigned int voff_a = static_cast<unsigned int>((group * kValueDim + row) * 2);
#pragma unroll
        for (int kk = 0; kk < kKeyDim / 16; ++kk)
#pragma unroll
            for (int s = 0; s < 4; ++s)
            {
                kda_c16_asm::buffer_store_dword(
                    update_state[kk][s], rsrc_b,
                    static_cast<unsigned int>(((kk * 16 + s) * kValueDim + col0) * 4), voff_b);
                kda_c16_asm::buffer_store_short(
                    static_cast<unsigned int>(float_to_bf16(transition_state[kk][s])), rsrc_a,
                    static_cast<unsigned int>(((kk * 16 + 4 * s) * kValueDim + col0) * 2), voff_a);
            }
        kda_c16_asm::wait_vmcnt_only<0>();
    }
}

#endif // FLASH_KDA_SEGMENT_PASS_CUH
