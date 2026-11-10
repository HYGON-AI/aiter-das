// SPDX-License-Identifier: MIT
//
// K2 kernel：每个 CTA 负责 (sequence b, head h) 的 kV16/gridDim.x 个 V 列
// （4 个 wave × 每 wave kK2VSlice=16 列），wave 之间协作搬运本 chunk 的 LDS。

#ifndef FLASH_KDA_K2_KERNEL_CUH
#define FLASH_KDA_K2_KERNEL_CUH

#include "flash_kda_k2_common.cuh"
#include "flash_kda_k2_step.cuh"

namespace
{

    // 每个 chunk 的发射序见 kda_k2_step 的注释；循环体不展开（等待立即数按每 chunk
    // 的在飞请求数推导）。
    template <bool FullChunks, bool StateBf16, bool IsVarlen, bool StateVFirst = false>
    __global__ __launch_bounds__(kK2Waves * 64) void kda_k2_kernel(
        const u16 *ws_kdqd,
        const u16 *ws_krgt,
        const u16 *ws_inv,
        const u16 *ws_mqk,
        const u16 *v,
        const float *beta_sigmoid,
        u16 *out,
        const state_scalar_t<StateBf16> *initial_state,
        state_scalar_t<StateBf16> *final_state,
        int sequence_count,
        int heads,
        int input_token_count,
        int workspace_head_stride_chunks,
        bool has_initial,
        bool store_final,
        const int64_t *sequence_info)
    {
        const int tid = static_cast<int>(threadIdx.x);
        const int lane = tid & 63;
        const int wave = tid >> 6;
        const int value_group = static_cast<int>(blockIdx.x) * kK2Waves + wave;
        const int bh = static_cast<int>(blockIdx.y);
        if (value_group >= kValueDim / kK2VSlice || bh >= sequence_count * heads)
            return;

        const int seq = bh / heads;
        const int head = bh % heads;
        // 定长语义：sequence_length = 总 token 数，各序列 chunk 槽按 seq*chunks 排布。
        // 变长语义：本 CTA 只处理 sequence_info[seq] 的一条序列，局部长度与 chunk 槽
        //           都取自 GPU metadata（AoS 三列：sequence_token_offset / L / chunk0）。
        int sequence_length = input_token_count;
        int io_batch = seq;
        int64_t sequence_chunk_offset =
            static_cast<int64_t>(seq) *
            ((static_cast<int64_t>(input_token_count) + kChunkSize - 1) / kChunkSize);
        if constexpr (IsVarlen)
        {
            const int64_t *info = sequence_info + static_cast<int64_t>(seq) * 3;
            const int64_t sequence_token_offset = info[0];
            sequence_length = static_cast<int>(info[1]); // 可表示范围由 host/producer 契约保证
            sequence_chunk_offset = info[2];
            io_batch = 0;
            // 空序列（L==0）不解引用 v/out：T_total=0 时数据指针可能为 nullptr。
            if (sequence_length > 0)
            {
                const int64_t scalar0 = sequence_token_offset * static_cast<int64_t>(heads);
                v += scalar0 * kValueDim; // u16 元素：token_offset*heads*128
                out += scalar0 * kValueDim;
            }
        }
        const int chunks = (sequence_length + kChunkSize - 1) / kChunkSize;
        const int col0 = value_group * kK2VSlice;
        const int vcol = col0 + lane;

        constexpr int kKdqdTileU16 = 8 * kTile * kTile; // 2048 u16 = 4 KiB
        // 16 B 对齐：ASM LDS 直写的落地地址要求 16 B 对齐（ds_read 侧同样受益）。
        __shared__ __align__(16) u16 s_kd[2 * kKdqdTileU16];
        __shared__ __align__(16) u16 s_qd[2 * kKdqdTileU16];
        __shared__ __align__(16) u16 s_krgt[kKrgtStrideU16]; // kr 8 tile + gt 1 tile

        float h_reg[kKeyDim / 16][4] = {};
        // 内部槽位是 `h_reg[kt][s] = state[16*kt + 4*group + s][col0 + row]`；
        // StateVFirst 只改外部 state 的物理布局，不改变任何计算或归约顺序。
        constexpr unsigned int kStateElemBytes = StateBf16 ? 2u : 4u;
        const unsigned int voff_state = static_cast<unsigned int>(
            flash_kda_state_layout::state_lane_offset<StateVFirst>(
                4 * (lane >> 4), lane & 15, kKeyDim, kValueDim) *
            kStateElemBytes);
        if (has_initial)
        {
            // 状态常驻 B fragment 布局：
            //   h_reg[kk][s] = state[kk*16 + 4*group + s][col0 + row]
            // 故装载是手写 MUBUF：soff 放 wave 均匀量（kk/col0），voff 放 per-lane 部分
            // （4*group*kValueDim + row，VK 下是 row*kKeyDim + 4*group）。
            const state_scalar_t<StateBf16> *state =
                initial_state + static_cast<int64_t>(seq * heads + head) * kKeyDim * kValueDim;
            const vec4_u32 rsrc_state = kda_c16_make_buffer_rsrc(state);
            if constexpr (StateVFirst)
            {
                // VK：一个 lane 的四个分量是**连续 4 个 K** ⇒ 一条宽读替代四条标量读。
                //   BF16：8 B（dwordx2）原始位读取后精确左移 16 位提升；
                //   FP32：16 B（dwordx4）直接进四个 FP32 寄存器。
                // 地址基址用 `key_s = 0` 的 wave 分量 + 已有的 per-lane voff。
                if constexpr (StateBf16)
                {
                    // 先把 8 条 8 B 读全部发出，再统一等待，最后做精确提升：
                    // BF16 的 `(raw & 0xffff) << 16` 是**消费**操作，必须在 vmcnt 收口之后，
                    // 否则读到的是尚未落地的 VGPR（FP32 分支可以省这一步，因为目标寄存器
                    // 就是 h_reg 本身、消费点在循环外的等待之后）。
                    unsigned long long raw[kKeyDim / 16];
#pragma unroll
                    for (int kk = 0; kk < kKeyDim / 16; ++kk)
                        kda_c16_asm::buffer_load_dwordx2(
                            raw[kk], rsrc_state,
                            static_cast<unsigned int>(
                                flash_kda_state_layout::state_wave_offset<true>(
                                    0, kk, col0, kKeyDim, kValueDim) *
                                kStateElemBytes),
                            voff_state);
                    kda_c16_asm::wait_vmcnt_only<0>();
#pragma unroll
                    for (int kk = 0; kk < kKeyDim / 16; ++kk)
                    {
                        h_reg[kk][0] = bf16_raw_to_float(static_cast<unsigned int>(raw[kk] & 0xffffu));
                        h_reg[kk][1] =
                            bf16_raw_to_float(static_cast<unsigned int>((raw[kk] >> 16) & 0xffffu));
                        h_reg[kk][2] =
                            bf16_raw_to_float(static_cast<unsigned int>((raw[kk] >> 32) & 0xffffu));
                        h_reg[kk][3] =
                            bf16_raw_to_float(static_cast<unsigned int>((raw[kk] >> 48) & 0xffffu));
                    }
                }
                else
                {
#pragma unroll
                    for (int kk = 0; kk < kKeyDim / 16; ++kk)
                    {
                        vec4_fp32 raw{};
                        kda_c16_asm::buffer_load_dwordx4(
                            raw, rsrc_state,
                            static_cast<unsigned int>(
                                flash_kda_state_layout::state_wave_offset<true>(
                                    0, kk, col0, kKeyDim, kValueDim) *
                                kStateElemBytes),
                            voff_state);
                        h_reg[kk][0] = raw[0];
                        h_reg[kk][1] = raw[1];
                        h_reg[kk][2] = raw[2];
                        h_reg[kk][3] = raw[3];
                    }
                    kda_c16_asm::wait_vmcnt_only<0>();
                }
            }
            else if constexpr (StateBf16)
            {
                // KV：四个分量跨 K 行，保留原有逐条 ushort 读取与分组等待。
                // BF16 入口：分组批量发 ushort load、显式等待后按 `(raw & 0xffff) << 16`
                // 精确提升 FP32；分组只是为了压住 raw 临时值与 h_reg 的峰值叠加。
                constexpr int kGroup = 2;
                unsigned int raw[kGroup][4];
#pragma unroll
                for (int kk0 = 0; kk0 < kKeyDim / 16; kk0 += kGroup)
                {
#pragma unroll
                    for (int kk = 0; kk < kGroup; ++kk)
#pragma unroll
                        for (int s = 0; s < 4; ++s)
                            kda_c16_asm::buffer_load_ushort(
                                raw[kk][s], rsrc_state,
                                static_cast<unsigned int>(
                                    flash_kda_state_layout::state_wave_offset<StateVFirst>(
                                        s, kk0 + kk, col0, kKeyDim, kValueDim) *
                                    kStateElemBytes),
                                voff_state);
                    kda_c16_asm::wait_vmcnt_only<0>();
#pragma unroll
                    for (int kk = 0; kk < kGroup; ++kk)
#pragma unroll
                        for (int s = 0; s < 4; ++s)
                            h_reg[kk0 + kk][s] = bf16_raw_to_float(raw[kk][s]);
                }
            }
            else
            {
#pragma unroll
                for (int kk = 0; kk < kKeyDim / 16; ++kk)
#pragma unroll
                    for (int s = 0; s < 4; ++s)
                        kda_c16_asm::buffer_load_dwordx1(
                            h_reg[kk][s], rsrc_state,
                            static_cast<unsigned int>(
                                flash_kda_state_layout::state_wave_offset<StateVFirst>(
                                    s, kk, col0, kKeyDim, kValueDim) *
                                kStateElemBytes),
                            voff_state);
                // 手写 asm 后编译器不再替我们插等待，此刻在飞只有这批状态装载 ⇒ 排空。
                kda_c16_asm::wait_vmcnt_only<0>();
            }
        }

        const u16 *ws_kd = ws_kdqd;
        const u16 *ws_qd = ws_kdqd + kQdOffsetU16;

        // 变长空序列：不发预取、不读 INV/Mqk/beta/V、不做 MMAC、不写 out，
        // 只保留"读自己的初态 → 共同终态 epilogue"。chunks 是 CTA 均匀量，
        // 因此这里的 if 不破坏 barrier 一致性。
        const bool run_pipeline = (!IsVarlen) || (chunks > 0);
        if (run_pipeline)
        {
            const int64_t p_base =
                static_cast<int64_t>(head) * workspace_head_stride_chunks +
                sequence_chunk_offset;
            if (chunks > 0)
            {
                // 序言：chunk 0 的 kd/qd 与 kr|gt 合并区一次发出。落地由 step 开头的
                // `wait_vmcnt_only<2>/<6>` + 紧随的 CTA barrier 收口，故此处只发不等。
                issue_kdqd_to_lds<kK2Waves>(tid, p_base, ws_kd, ws_qd, s_kd, s_qd);
                issue_krgt_to_lds<kK2Waves>(tid, p_base, ws_krgt, s_krgt);
            }
            int stage = 0;
            int64_t workspace_chunk_index = p_base;
            // 禁止展开本循环：账本（顶部 vmcnt(2/6)、gt/kr 读前的 vmcnt(12/10)、
            // 消费窗口 3/1 与 2/0）全按"每 chunk 在飞数"手推，展开两份即失效。
#pragma unroll 1
            for (int chunk = 0; chunk < chunks; ++chunk)
            {
                __builtin_amdgcn_sched_barrier(0);
                asm volatile("s_barrier" ::: "memory"); // A: 跨 wave 发布 + 保护 WAR
                __builtin_amdgcn_sched_barrier(0);
                // 整个 chunk 体都在 step 里：取数段 (1)(2)(3) → 边界 1（lgkmcnt）→
                // 第一组 MMAC → 边界 2（vmcnt）→ 第二组计算 → 写回段 → C 屏障 + 发布下一代。
                kda_k2_step<FullChunks>(
                    tid, workspace_chunk_index + 1, (chunk + 1) < chunks,
                    ws_kd, ws_qd, ws_krgt,
                    s_kd + (stage ^ 1) * kKdqdTileU16,
                    s_qd + (stage ^ 1) * kKdqdTileU16,
                    s_kd + stage * kKdqdTileU16, s_qd + stage * kKdqdTileU16,
                    reinterpret_cast<const float *>(s_krgt + kDecayOffsetU16),
                    s_krgt,
                    ws_inv + workspace_chunk_index * kChunkSize * kChunkSize,
                    ws_mqk + workspace_chunk_index * kChunkSize * kChunkSize,
                    v, beta_sigmoid + workspace_chunk_index * kChunkSize, out,
                    h_reg, col0,
                    io_batch, head, chunk * kChunkSize, heads, sequence_length);
                stage ^= 1;
                ++workspace_chunk_index;
            }
        }

        if (store_final)
        {
            // 与装载对称的手写 MUBUF 写回：soff 放 wave 均匀量、voff 放 per-lane；
            // store 也记 vmcnt，kernel 结束前自己收口。
            state_scalar_t<StateBf16> *state =
                final_state + static_cast<int64_t>(seq * heads + head) * kKeyDim * kValueDim;
            const vec4_u32 rsrc_st = kda_c16_make_buffer_rsrc(state);
            const int voff_st = static_cast<int>(voff_state);
            if constexpr (StateVFirst)
            {
                // VK 出口：先把四个分量在原位置打包，再一条宽写；RNE 舍入逐值保留
                // （BF16 仍按元素做 RNE，只是打包成 8 B 一次写）。
                if constexpr (StateBf16)
                {
#pragma unroll
                    for (int kk = 0; kk < kKeyDim / 16; ++kk)
                    {
                        unsigned long long packed = 0;
#pragma unroll
                        for (int s = 0; s < 4; ++s)
                            packed |= static_cast<unsigned long long>(
                                          float_to_bf16_16(h_reg[kk][s])) << (16 * s);
                        kda_c16_asm::buffer_store_dwordx2(
                            packed, rsrc_st,
                            static_cast<unsigned int>(
                                flash_kda_state_layout::state_wave_offset<true>(
                                    0, kk, col0, kKeyDim, kValueDim) *
                                kStateElemBytes),
                            voff_st);
                    }
                }
                else
                {
#pragma unroll
                    for (int kk = 0; kk < kKeyDim / 16; ++kk)
                    {
                        vec4_fp32 packed{};
                        packed[0] = h_reg[kk][0];
                        packed[1] = h_reg[kk][1];
                        packed[2] = h_reg[kk][2];
                        packed[3] = h_reg[kk][3];
                        kda_c16_asm::buffer_store_dwordx4(
                            packed, rsrc_st,
                            static_cast<unsigned int>(
                                flash_kda_state_layout::state_wave_offset<true>(
                                    0, kk, col0, kKeyDim, kValueDim) *
                                kStateElemBytes),
                            voff_st);
                    }
                }
                kda_c16_asm::wait_vmcnt_only<0>();
            }
            else if constexpr (StateBf16)
            {
                // BF16 出口：RNE 转换后只写低 16 位，不能用 dword 覆盖相邻元素。
#pragma unroll
                for (int kk = 0; kk < kKeyDim / 16; ++kk)
#pragma unroll
                    for (int s = 0; s < 4; ++s)
                    {
                        const unsigned int bits =
                            static_cast<unsigned int>(float_to_bf16_16(h_reg[kk][s]));
                        kda_c16_asm::buffer_store_short(
                            bits, rsrc_st,
                            static_cast<unsigned int>(
                                flash_kda_state_layout::state_wave_offset<StateVFirst>(
                                    s, kk, col0, kKeyDim, kValueDim) *
                                kStateElemBytes),
                            voff_st);
                    }
                kda_c16_asm::wait_vmcnt_only<0>();
            }
            else
            {
#pragma unroll
                for (int kk = 0; kk < kKeyDim / 16; ++kk)
#pragma unroll
                    for (int s = 0; s < 4; ++s)
                        kda_c16_asm::buffer_store_dword(
                            h_reg[kk][s], rsrc_st,
                            static_cast<unsigned int>(
                                flash_kda_state_layout::state_wave_offset<StateVFirst>(
                                    s, kk, col0, kKeyDim, kValueDim) *
                                kStateElemBytes),
                            voff_st);
                kda_c16_asm::wait_vmcnt_only<0>();
            }
        }
    }

} // namespace

#endif // FLASH_KDA_K2_KERNEL_CUH
