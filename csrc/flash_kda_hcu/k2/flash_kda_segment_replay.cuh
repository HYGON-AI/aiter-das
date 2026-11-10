// SPDX-License-Identifier: MIT
//
// Replay：用 scan 得到的 segment_initial_states 逐段重放，产出 out 与 final_state。

#ifndef FLASH_KDA_SEGMENT_REPLAY_CUH
#define FLASH_KDA_SEGMENT_REPLAY_CUH

#include "flash_kda_segment_common.cuh"

// Replay 的输入/输出：读 ws_kdqd（kd 半区 + qd 半区）、ws_krgt（kr|gt 合并区）、
// ws_inv、ws_mqk、v 与 segment_initial_states，写 out 与 final_state。
//
// 状态常驻 B fragment 布局：`h[k = kk*16 + 4*group + s][v = col0 + row]`。依据是 MMAC 的
// fragment 契约互为「转置读」：
//   A fragment: a[s] = T[m = row][k = group + 4s]
//   B fragment: b[s] = T[k = group + 4s][n = row]
// 于是同一物理 tile 的「A 布局读取」等于「其转置的 B 布局读取」，状态可以按 B 布局
// 常驻而不需要每 chunk 转置：
//   kh^T   = h^T · kd^T   -> opus_mmac_bf16(state_frag, kd A 布局读, acc)
//   U^T    = u^T · inv^T  -> opus_mmac_f16(u^T, inv A 布局读, 0)
//   upd^T  = U^T · kr^T   -> opus_mmac_bf16(U^T, kr A 布局读, 0)（输出即下一轮状态布局）
//
// 缓冲与发布约束：kd/qd 双缓冲，kr|gt 单共享槽（覆盖前需全体 wave 完成本代读取）；
// kd/qd/kr/gt 由 CTA 四 wave 协作搬进同一块 LDS，每个 wave 先排空自己的请求、
// 再 `s_barrier` 发布，然后才 `ds_read`。V 与状态按 V 列切分，不参与合并。
//
// Replay：四 wave、单状态，三条矩阵链
//   M1（BF16）：kd、qd 各作用于 state B-fragment
//   M2（FP16）：U = u·inv^T；out = oq + U·mqk^T
//   M3（BF16）：update = U·kr^T，直接得到下一轮 state 的 B-fragment
// LDS：kd 双槽 8 KiB + qd 双槽 8 KiB + kr|gt 单共享槽 4608 B = 20992 B。
// 外部终态按 StateVFirst 选择布局；段初态（segment_initial_states）恒为自然 [K,V]。
template <bool StateBf16, bool StateVFirst = false>
__global__ __launch_bounds__(seg4w::kWaves * 64) void kda_replay_c16_4w(
    const unsigned short *ws_kdqd, // kd 半区 + qd 半区（+4 KiB）
    const unsigned short *ws_krgt, // kr|gt 合并区
    const unsigned short *ws_inv,
    const unsigned short *ws_mqk,
    const unsigned short *v,
    const float *beta_sigmoid,
    unsigned short *out,
    state_scalar_t<StateBf16> *final_state,
    const float *segment_initial_states,
    int sequence_count,
    int heads,
    int input_token_count,
    int workspace_head_stride_chunks,
    int segment_count,
    int chunks_per_segment,
    bool store_final)
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
    __shared__ __align__(16) unsigned short s_qd[2 * seg4w::kKdqdTileU16];
    __shared__ __align__(16) unsigned short s_krgt[kKrgtStrideU16];

    // ===== 段入口：FP32 segment_initial_states → B-fragment（h[k = kk*16+4*group+s][v = col0+row]）=====
    // 段初态是中间契约（自然 [K,V] FP32），布局与外部 state 无关；
    // 地址算式与普通 K2 的 state 装载一致：soffset 放 wave 均匀的 tile/列基址，
    // per-lane 的 (row,group) 只进 voffset。
    float h_reg[kKeyDim / 16][4];
    {
        const float *state =
            segment_initial_states + (static_cast<int64_t>(segment) * bh_count + bh) * kKeyDim * kValueDim;
        const seg4w::vec4_u32 rsrc = seg4w::make_rsrc(state);
        const unsigned int voff =
            static_cast<unsigned int>((4 * (lane >> 4) * kValueDim + (lane & 15)) * 4);
#pragma unroll
        for (int kk = 0; kk < kKeyDim / 16; ++kk)
#pragma unroll
            for (int s = 0; s < 4; ++s)
                kda_c16_asm::buffer_load_dwordx1(
                    h_reg[kk][s], rsrc,
                    static_cast<unsigned int>(((kk * 16 + s) * kValueDim + col0) * 4), voff);
        // 段入口状态读是本 kernel 循环外唯一的 VM 请求，必须在序言之前排空。
        kda_c16_asm::wait_vmcnt_only<0>();
    }

    // ===== 序言：本段首 chunk 的 kd/qd → 槽 0；kr|gt → 单共享槽 =====
    int64_t p = static_cast<int64_t>(head) * workspace_head_stride_chunks +
                static_cast<int64_t>(b) * chunk_count + chunk_begin;
    seg4w::issue_kdqd<true>(tid, p, ws_kdqd, ws_kdqd + kQdOffsetU16, s_kd, s_qd);
    seg4w::issue_krgt(tid, p, ws_krgt, s_krgt);

    int stage = 0;
    // 禁止展开：所有立即数按"每 chunk 在飞数"手推（与普通 K2 同因）。
#pragma unroll 1
    for (int chunk = chunk_begin; chunk < chunk_end; ++chunk, p += 1)
    {
        const bool is_first = (chunk == chunk_begin);
        const bool has_next = (chunk + 1 < chunk_end);
        const int token_base = chunk * kChunkSize;
        const unsigned short *const kd_cur = s_kd + stage * seg4w::kKdqdTileU16;
        const unsigned short *const qd_cur = s_qd + stage * seg4w::kKdqdTileU16;

        // ===== (0) 顶部：等本代 kd/qd 直写落地（VM 门控；必须在 ds_read 之前）=====
        if (is_first)
            kda_c16_asm::wait_vmcnt_only<2>();
        else
            kda_c16_asm::wait_vmcnt_only<6>();
        kda_c16_asm::sched_pin();
        asm volatile("s_barrier" ::: "memory"); // A：跨 wave 发布（kd/qd 协作搬运）
        kda_c16_asm::sched_pin();

        // ===== 本代 V：4 × ushort（无效 lane 夹到最后一个有效 token，仍发 4 条）=====
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

        // ===== (1) 本代 kd/qd 的 ds_read（各 8 条 ds_read_b64）=====
        unsigned long long rk[8];
        unsigned long long rq[8];
        {
            const unsigned int kd_lane = kda_c16_asm::lds_byte_addr(
                kd_cur, static_cast<unsigned int>(kda_c16_kdqd_seg_cons_u16(row, group) * 2));
            const unsigned int qd_lane = kda_c16_asm::lds_byte_addr(
                qd_cur, static_cast<unsigned int>(kda_c16_kdqd_seg_cons_u16(row, group) * 2));
#pragma unroll
            for (int kt = 0; kt < kKeyDim / 16; ++kt)
                kda_c16_asm::ds_read_b64(kd_lane + static_cast<unsigned int>(kt) * 512u, rk[kt]);
#pragma unroll
            for (int kt = 0; kt < kKeyDim / 16; ++kt)
                kda_c16_asm::ds_read_b64(qd_lane + static_cast<unsigned int>(kt) * 512u, rq[kt]);
        }

        // ===== (2) 本代全局寄存器操作数：beta 4 + inv 1 + mqk 1 =====
        float beta_reg[4];
        unsigned long long inv_reg;
        unsigned long long mqk_reg;
        {
            const seg4w::vec4_u32 rsrc_beta =
                seg4w::make_rsrc(beta_sigmoid + p * kChunkSize);
            const seg4w::vec4_u32 rsrc_inv =
                seg4w::make_rsrc(ws_inv + p * kChunkSize * kChunkSize);
            const seg4w::vec4_u32 rsrc_mqk =
                seg4w::make_rsrc(ws_mqk + p * kChunkSize * kChunkSize);
            const int packed_voff = (row * 4 + group) * 8;
#pragma unroll
            for (int s = 0; s < 4; ++s)
                kda_c16_asm::buffer_load_dwordx1(beta_reg[s], rsrc_beta, 0u,
                                                 (group + 4 * s) * 4);
            kda_c16_asm::buffer_load_dwordx2(inv_reg, rsrc_inv, 0u, packed_voff);
            kda_c16_asm::buffer_load_dwordx2(mqk_reg, rsrc_mqk, 0u, packed_voff);
        }

        // ===== (3) 下一代 kd/qd 直写（备用槽；必须排在本代 ds_read 之后）=====
        if (has_next)
            seg4w::issue_kdqd<true>(tid, p + 1, ws_kdqd, ws_kdqd + kQdOffsetU16,
                                    s_kd + (stage ^ 1) * seg4w::kKdqdTileU16,
                                    s_qd + (stage ^ 1) * seg4w::kKdqdTileU16);

        // ===== 边界 1：收口本代 16 条 ds_read（此刻 LGKM 只有它们）=====
        kda_c16_asm::wait_lgkmcnt_only<0>();

        // ===== 第一组 MMAC：kh^T = h^T·kd^T / oq^T = h^T·qd^T =====
        vec4_fp32 kh_acc{0, 0, 0, 0};
        vec4_fp32 oq_acc{0, 0, 0, 0};
#pragma unroll
        for (int kt = 0; kt < kKeyDim / 16; ++kt)
        {
            const auto a_k = __builtin_bit_cast(flash_kda_k2_fragments::vec4_bf16, rk[kt]);
            const auto a_q = __builtin_bit_cast(flash_kda_k2_fragments::vec4_bf16, rq[kt]);
            flash_kda_k2_fragments::vec4_bf16 b_h{};
#pragma unroll
            for (int s = 0; s < 4; ++s)
                b_h[s] = flash_kda_k2_fragments::float_to_bf16_rne_fast(h_reg[kt][s]);
            kda_c16_asm::mmac_bf16(kh_acc, b_h, a_k);
            kda_c16_asm::mmac_bf16(oq_acc, b_h, a_q);
        }

        // ===== 收口本代 kr|gt 的搬运（顶部故意把它留在飞）再发布 =====
        // 在飞（老→新）= store4 + krgt2 + beta4/v4/inv1/mqk1 + kd/qd(c+1)2 = 18（有 next）
        //                = store4 + krgt2 + 10（无 next，共 16）
        // ⇒ 12 / 10 恰好退掉最老 6 条（store4 + krgt2），krgt(c) 落地。
        kda_c16_asm::sched_pin();
        if (has_next)
            kda_c16_asm::wait_vmcnt_only<12>();
        else
            kda_c16_asm::wait_vmcnt_only<10>();
        kda_c16_asm::sched_pin();
        asm volatile("s_barrier" ::: "memory"); // B：跨 wave 发布 kr|gt
        kda_c16_asm::sched_pin();

        // ===== 分批取 gt/kr 的 A 半（pair 0-1）；B 半在 M2 之后发 =====
        vec4_fp32 gt_reg[8];
        unsigned long long kr_reg[8];
        const unsigned int gt_base =
            kda_c16_asm::lds_byte_addr(s_krgt + kDecayOffsetU16, 0u);
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

        // ===== 首次消费 beta/v/inv 前：退掉 beta4 + v4 + inv1 这 9 条 =====
        // 在飞 = 上述 9 条 + mqk 1 + 下一代 kd/qd 2 ⇒ 有 next 留 3、无 next 留 1，mqk 与下一代直写继续在飞。
        kda_c16_asm::sched_pin();
        if (has_next)
            kda_c16_asm::wait_vmcnt_only<3>();
        else
            kda_c16_asm::wait_vmcnt_only<1>();
        kda_c16_asm::ready8<3, 15>(beta_reg[0], beta_reg[1], beta_reg[2], beta_reg[3],
                                   v_raw[0], v_raw[1], v_raw[2], v_raw[3]);
        kda_c16_asm::sched_pin();

        // ===== 第二组：u / U^T =====
        float u[4];
#pragma unroll
        for (int s = 0; s < 4; ++s)
        {
            const int token_s = token_base + group + 4 * s;
            const bool valid_s = token_s < input_token_count;
            const float value =
                valid_s ? bf16_to_float(static_cast<unsigned short>(v_raw[s] & 0xffffu)) : 0.0f;
            u[s] = (value - kh_acc[s]) * (valid_s ? beta_reg[s] : 0.0f);
        }
        flash_kda_k2_fragments::vec4_bf16 a_u{};
#pragma unroll
        for (int s = 0; s < 4; ++s)
            a_u[s] = float_to_bf16(u[s]);
        const auto a_inv = __builtin_bit_cast(flash_kda_k2_fragments::vec4_bf16, inv_reg);
        vec4_fp32 U_acc{0, 0, 0, 0};
        kda_c16_asm::mmac_bf16(U_acc, a_u, a_inv);
        float U_float[4];
        unsigned short U_f16[4];
        unsigned short U_bf[4];
#pragma unroll
        for (int s = 0; s < 4; ++s)
        {
            U_float[s] = U_acc[s];
            U_f16[s] = float_to_bf16(U_float[s]);
            U_bf[s] = flash_kda_k2_fragments::float_to_bf16_rne_fast(U_float[s]);
        }
        vec4_fp32 output_acc = oq_acc;

        // ===== 分批取 gt/kr 的 B 半（pair 2-3）：给 A 半多一个落地窗口 =====
        kda_c16_asm::sched_pin();
#pragma unroll
        for (int i = 4; i < 8; ++i)
            kda_c16_asm::ds_read_b128(gt_base + static_cast<unsigned int>(i * 16 + group * 4) * 4u,
                                      gt_reg[i]);
#pragma unroll
        for (int tile = 4; tile < 8; ++tile)
            kda_c16_asm::ds_read_b64(kr_base + static_cast<unsigned int>(tile) * 512u,
                                     kr_reg[tile]);

        // ===== 消费 mqk 前：在飞 = mqk1 + kd/qd(c+1)2 ⇒ 2 留 2（无 next 时 0）=====
        kda_c16_asm::sched_pin();
        if (has_next)
            kda_c16_asm::wait_vmcnt_only<2>();
        else
            kda_c16_asm::wait_vmcnt_only<0>();
        kda_c16_asm::ready1<2, 15>(mqk_reg);
        kda_c16_asm::sched_pin();

        const auto a_mqk = __builtin_bit_cast(flash_kda_k2_fragments::vec4_bf16, mqk_reg);
        flash_kda_k2_fragments::vec4_bf16 a_U_f16{};
#pragma unroll
        for (int s = 0; s < 4; ++s)
            a_U_f16[s] = U_f16[s];
        kda_c16_asm::mmac_bf16(output_acc, a_U_f16, a_mqk);

        // ===== 分级 LGKM：先退 A 半（8 条），做 pair 0-1；再退 B 半，做 pair 2-3 =====
        kda_c16_asm::wait_lgkmcnt_only<8>();
        kda_c16_asm::sched_pin();
#pragma unroll
        for (int pair = 0; pair < 2; ++pair)
        {
            const auto a_kr0 =
                __builtin_bit_cast(flash_kda_k2_fragments::vec4_bf16, kr_reg[pair * 2]);
            const auto a_kr1 =
                __builtin_bit_cast(flash_kda_k2_fragments::vec4_bf16, kr_reg[pair * 2 + 1]);
            flash_kda_k2_fragments::vec4_bf16 a_U_bf{};
#pragma unroll
            for (int s = 0; s < 4; ++s)
                a_U_bf[s] = U_bf[s];
            vec4_fp32 update0{0, 0, 0, 0};
            vec4_fp32 update1{0, 0, 0, 0};
            kda_c16_asm::mmac_bf16(update0, a_U_bf, a_kr0);
            kda_c16_asm::mmac_bf16(update1, a_U_bf, a_kr1);
            const vec4_fp32 &d0 = gt_reg[pair * 2];
            const vec4_fp32 &d1 = gt_reg[pair * 2 + 1];
            h_reg[pair * 2][0] = d0[0] * h_reg[pair * 2][0] + update0[0];
            h_reg[pair * 2][1] = d0[1] * h_reg[pair * 2][1] + update0[1];
            h_reg[pair * 2][2] = d0[2] * h_reg[pair * 2][2] + update0[2];
            h_reg[pair * 2][3] = d0[3] * h_reg[pair * 2][3] + update0[3];
            h_reg[pair * 2 + 1][0] = d1[0] * h_reg[pair * 2 + 1][0] + update1[0];
            h_reg[pair * 2 + 1][1] = d1[1] * h_reg[pair * 2 + 1][1] + update1[1];
            h_reg[pair * 2 + 1][2] = d1[2] * h_reg[pair * 2 + 1][2] + update1[2];
            h_reg[pair * 2 + 1][3] = d1[3] * h_reg[pair * 2 + 1][3] + update1[3];
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
            flash_kda_k2_fragments::vec4_bf16 a_U_bf{};
#pragma unroll
            for (int s = 0; s < 4; ++s)
                a_U_bf[s] = U_bf[s];
            const vec4_fp32 update0 =
                flash_kda_k2_fragments::opus_mmac_bf16(a_U_bf, a_kr0, vec4_fp32{0, 0, 0, 0});
            const vec4_fp32 update1 =
                flash_kda_k2_fragments::opus_mmac_bf16(a_U_bf, a_kr1, vec4_fp32{0, 0, 0, 0});
            const vec4_fp32 &d0 = gt_reg[pair * 2];
            const vec4_fp32 &d1 = gt_reg[pair * 2 + 1];
            h_reg[pair * 2][0] = d0[0] * h_reg[pair * 2][0] + update0[0];
            h_reg[pair * 2][1] = d0[1] * h_reg[pair * 2][1] + update0[1];
            h_reg[pair * 2][2] = d0[2] * h_reg[pair * 2][2] + update0[2];
            h_reg[pair * 2][3] = d0[3] * h_reg[pair * 2][3] + update0[3];
            h_reg[pair * 2 + 1][0] = d1[0] * h_reg[pair * 2 + 1][0] + update1[0];
            h_reg[pair * 2 + 1][1] = d1[1] * h_reg[pair * 2 + 1][1] + update1[1];
            h_reg[pair * 2 + 1][2] = d1[2] * h_reg[pair * 2 + 1][2] + update1[2];
            h_reg[pair * 2 + 1][3] = d1[3] * h_reg[pair * 2 + 1][3] + update1[3];
        }

        // ===== 写回段：out 的 4 个 bf16（地址在这里算）=====
        {
            const seg4w::vec4_u32 rsrc_out = seg4w::make_rsrc(out);
            const unsigned int out_soff = static_cast<unsigned int>(
                ((static_cast<int64_t>(b) * input_token_count + token_base) * heads + head) * kValueDim * 2);
#pragma unroll
            for (int s = 0; s < 4; ++s)
            {
                const int token_s = token_base + group + 4 * s;
                if (token_s < input_token_count)
                {
                    const unsigned int bits =
                        static_cast<unsigned int>(float_to_bf16(output_acc[s]));
                    kda_c16_asm::buffer_store_short(
                        bits, rsrc_out, out_soff, ((group + 4 * s) * heads * kValueDim + vcol) * 2);
                }
            }
        }

        // ===== 单共享槽覆盖前：本代 kr/gt 的 LDS 读必须全部完成（WAR）=====
        kda_c16_asm::wait_lgkmcnt_only<0>();
        kda_c16_asm::sched_pin();
        asm volatile("s_barrier" ::: "memory"); // C：可见性会合 + 保护单共享槽 WAR
        kda_c16_asm::sched_pin();
        if (has_next)
            seg4w::issue_krgt(tid, p + 1, ws_krgt, s_krgt);

        stage ^= 1;
    }

    // ===== 末段写外部终态（仅最后 segment 且请求）=====
    if (store_final && segment == segment_count - 1)
    {
        state_scalar_t<StateBf16> *state_out =
            final_state + (static_cast<int64_t>(b) * heads + head) * kKeyDim * kValueDim;
        constexpr unsigned int kElemBytes = StateBf16 ? 2u : 4u;
        const seg4w::vec4_u32 rsrc = seg4w::make_rsrc(state_out);
        const unsigned int voff = static_cast<unsigned int>(
            flash_kda_state_layout::state_lane_offset<StateVFirst>(
                4 * (lane >> 4), lane & 15, kKeyDim, kValueDim) *
            kElemBytes);
#pragma unroll
        for (int kk = 0; kk < kKeyDim / 16; ++kk)
        {
            if constexpr (StateVFirst)
            {
                // VK 出口：四个分量是连续 K ⇒ 一条宽写；RNE 仍逐值执行。
                const unsigned int soff = static_cast<unsigned int>(
                    flash_kda_state_layout::state_wave_offset<true>(
                        0, kk, col0, kKeyDim, kValueDim) *
                    kElemBytes);
                if constexpr (StateBf16)
                {
                    unsigned long long packed = 0;
#pragma unroll
                    for (int s = 0; s < 4; ++s)
                        packed |= static_cast<unsigned long long>(
                                      float_to_bf16(h_reg[kk][s])) << (16 * s);
                    kda_c16_asm::buffer_store_dwordx2(packed, rsrc, soff, voff);
                }
                else
                {
                    vec4_fp32 packed{};
                    packed[0] = h_reg[kk][0];
                    packed[1] = h_reg[kk][1];
                    packed[2] = h_reg[kk][2];
                    packed[3] = h_reg[kk][3];
                    kda_c16_asm::buffer_store_dwordx4(packed, rsrc, soff, voff);
                }
            }
            else
            {
#pragma unroll
                for (int s = 0; s < 4; ++s)
                {
                    const unsigned int soff = static_cast<unsigned int>(
                        flash_kda_state_layout::state_wave_offset<StateVFirst>(
                            s, kk, col0, kKeyDim, kValueDim) *
                        kElemBytes);
                    if constexpr (StateBf16)
                        kda_c16_asm::buffer_store_short(
                            static_cast<unsigned int>(float_to_bf16(h_reg[kk][s])), rsrc, soff,
                            voff);
                    else
                        kda_c16_asm::buffer_store_dword(h_reg[kk][s], rsrc, soff, voff);
                }
            }
        }
        kda_c16_asm::wait_vmcnt_only<0>();
    }
}

#endif // FLASH_KDA_SEGMENT_REPLAY_CUH
