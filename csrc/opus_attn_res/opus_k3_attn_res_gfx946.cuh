// SPDX-License-Identifier: MIT
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.
#pragma once

// gfx946 / Shaobo-specific correctness adaptations for Opus K3 AttnRes.
//
// Keep this helper separate from the gfx936 production kernel. The Shaobo Perf
// Model exposed incorrect output when the generic conditional C++ BF16 RNE
// conversion was lowered inside the large AlignedGeneral template. The Opus
// number<3> path preserves RNE semantics with an explicit, already-supported
// branchless VOP sequence and avoids the failing large-kernel divergent CFG.
// Standalone PMD probes pass v_cmp_eq_u32_sdwa, an s[0:1] condition mask, and
// the complete saveexec/restore sequence (including 32 consecutive repeats),
// so no individual opcode should be described as unsupported.

namespace opus_k3_attn_res_gfx946 {

#if defined(__HIP_DEVICE_COMPILE__) && defined(__gfx946__)
OPUS_D __forceinline__ opus::vector_t<opus::bf16_t, 8>
fp32x8_to_bf16_rne_asm(opus::vector_t<opus::fp32_t, 8> x)
{
    return {opus::fp32_to_bf16(x[0], opus::number<3>{}),
            opus::fp32_to_bf16(x[1], opus::number<3>{}),
            opus::fp32_to_bf16(x[2], opus::number<3>{}),
            opus::fp32_to_bf16(x[3], opus::number<3>{}),
            opus::fp32_to_bf16(x[4], opus::number<3>{}),
            opus::fp32_to_bf16(x[5], opus::number<3>{}),
            opus::fp32_to_bf16(x[6], opus::number<3>{}),
            opus::fp32_to_bf16(x[7], opus::number<3>{})};
}
#endif

} // namespace opus_k3_attn_res_gfx946
