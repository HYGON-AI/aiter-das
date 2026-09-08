# SPDX-License-Identifier: Apache-2.0

# Adapted from https://github.com/sgl-project/sglang/pull/3730
import itertools
import unittest
import triton
import torch

from aiter.fused_moe_c import moe_c_fused_experts,moe_align_block_size,moe_kernel_prepare_input,triton_moe_sum
from typing import Optional
import torch.nn.functional as F
from aiter.ops.shuffle import w8a16_marlin_weight_1,w8a16_marlin_weight_2
import triton.language as tl
import aiter


def compare_tensors(
    tensor1: torch.Tensor,
    tensor2: torch.Tensor,
    atol: float = 1e-2,
    rtol: float = 1e-2
) -> None:
    """张量对比工具（保留原逻辑）"""
    if not isinstance(tensor1, torch.Tensor) or not isinstance(tensor2, torch.Tensor):
        raise TypeError("输入必须是PyTorch张量")
    if tensor1.shape != tensor2.shape:
        raise ValueError(f"形状不匹配! {tensor1.shape} vs {tensor2.shape}")
    if tensor1.device != tensor2.device:
        tensor2 = tensor2.to(tensor1.device)

    abs_diff = torch.abs(tensor1 - tensor2)
    denom = torch.maximum(torch.abs(tensor1), torch.abs(tensor2))
    rel_diff = abs_diff / (denom + 1e-12)
    match_mask = (abs_diff <= atol) | (rel_diff <= rtol)

    total = tensor1.numel()
    matched = match_mask.sum().item()
    mismatched = total - matched
    max_abs_diff = abs_diff.max().item()

    print("=" * 60)
    print(f"张量对比 | 总元素:{total} | 不匹配:{mismatched} | 最大误差:{max_abs_diff:.6f}")
    print("=" * 60)

def generate_unique_int_tensor(m, topk, low=0, high=256):
    """生成[m, topk]不重复整数张量"""
    if topk > (high - low):
        raise ValueError(f"topk ({topk}) 超过范围")
    tensor = torch.zeros((m, topk), dtype=torch.int)
    for i in range(m):
        row = torch.randperm(high - low)[:topk] + low
        tensor[i] = row
    return tensor

def _fused_moe_helper(
    m: int, n: int, k: int, n2: int, k2: int, topk: int, E: int,
    out_dtype: torch.dtype = torch.bfloat16,  # 统一默认类型
    device: str = "cuda",
    per_channel_quant: bool = True
):
    # ===================== 修复1：输入类型统一为 out_dtype (bf16) =====================
    input_data = torch.randn((m, k), device=device, dtype=out_dtype) / 100000

    # 权重int8保持不变
    weight1 = torch.randint(-127, 127, (E, n, k), device=device, dtype=torch.int8)
    weight2 = torch.randint(-127, 127, (E, n2, k2), device=device, dtype=torch.int8)

    # ===================== 修复2：权重scale 类型=输入类型 (bf16)，解决类型报错！ =====================
    if per_channel_quant:
        weight1_scale = torch.randn((E, n, 1), device=device, dtype=out_dtype)
        weight2_scale = torch.randn((E, n2, 1), device=device, dtype=out_dtype)
    else:
        weight1_scale = torch.randn((E, n, 1), device=device, dtype=out_dtype)
        weight2_scale = torch.randn((E, n2, 1), device=device, dtype=out_dtype)

    # topk权重/ID
    tensor = torch.rand((m, topk), device=device)
    topk_weights = F.softmax(tensor, dim=1)
    topk_ids = generate_unique_int_tensor(m=m, topk=topk, low=0, high=E).to(device)

    # 权重重排
    w1_marlin = w8a16_marlin_weight_1(weight1)
    w2_marlin = w8a16_marlin_weight_2(weight2)

    return input_data, w1_marlin, w2_marlin, weight1, weight2, weight1_scale, weight2_scale, topk_weights, topk_ids

# ------------------- Triton Kernel 原逻辑保留 -------------------
@triton.jit
def fused_moe_kernel(
    a_ptr, b_ptr, c_ptr, a_scale_ptr, b_scale_ptr, topk_weights_ptr,
    sorted_token_ids_ptr, expert_ids_ptr, num_tokens_post_padded_ptr,
    N, K, EM, num_valid_tokens,
    stride_am, stride_ak, stride_be, stride_bk, stride_bn, stride_cm, stride_cn,
    stride_asm, stride_ask, stride_bse, stride_bsk, stride_bsn,
    group_n: tl.constexpr, group_k: tl.constexpr,
    BLOCK_SIZE_M: tl.constexpr, BLOCK_SIZE_N: tl.constexpr, BLOCK_SIZE_K: tl.constexpr,
    GROUP_SIZE_M: tl.constexpr, MUL_ROUTED_WEIGHT: tl.constexpr, top_k: tl.constexpr,
    compute_type: tl.constexpr, use_fp8_w8a8: tl.constexpr, use_int8_w8a8: tl.constexpr,
    use_int8_w8a16: tl.constexpr, per_channel_quant: tl.constexpr, delta: tl.constexpr,
):
    pid = tl.program_id(axis=0)
    num_pid_n = tl.cdiv(N, BLOCK_SIZE_N)
    pid_m = pid // num_pid_n
    pid_n = pid % num_pid_n

    num_tokens_post_padded = tl.load(num_tokens_post_padded_ptr)
    if pid_m * BLOCK_SIZE_M >= num_tokens_post_padded:
        return
    offs_token_id = pid_m * BLOCK_SIZE_M + tl.arange(0, BLOCK_SIZE_M).to(tl.int64)
    offs_token = tl.load(sorted_token_ids_ptr + offs_token_id)
    token_mask = offs_token < num_valid_tokens

    offs_bn = (pid_n * BLOCK_SIZE_N + tl.arange(0, BLOCK_SIZE_N).to(tl.int64)) % N
    offs_k = tl.arange(0, BLOCK_SIZE_K)
    a_ptrs = a_ptr + (offs_token[:, None] // top_k * stride_am + offs_k[None, :] * stride_ak)

    off_experts = tl.load(expert_ids_ptr + pid_m // delta).to(tl.int64)
    b_ptrs = b_ptr + off_experts * stride_be + (offs_k[:, None] * stride_bk + offs_bn[None, :] * stride_bn)

    if use_int8_w8a16:
        b_scale_ptrs = b_scale_ptr + off_experts * stride_bse + offs_bn[None, :] * stride_bsn
        b_scale = tl.load(b_scale_ptrs)

    accumulator = tl.zeros((BLOCK_SIZE_M, BLOCK_SIZE_N), dtype=tl.float32)
    for k in range(0, tl.cdiv(K, BLOCK_SIZE_K)):
        a = tl.load(a_ptrs, mask=token_mask[:, None] & (offs_k[None, :] < K - k * BLOCK_SIZE_K), other=0.0)
        b = tl.load(b_ptrs, mask=offs_k[:, None] < K - k * BLOCK_SIZE_K, other=0.0)
        if use_int8_w8a16:
            accumulator = tl.dot(a, b.to(compute_type), acc=accumulator)
        else:
            accumulator += tl.dot(a, b)
        a_ptrs += BLOCK_SIZE_K * stride_ak
        b_ptrs += BLOCK_SIZE_K * stride_bk

    if MUL_ROUTED_WEIGHT:
        moe_weight = tl.load(topk_weights_ptr + offs_token, mask=token_mask, other=0)
        accumulator = accumulator * moe_weight[:, None]
    if use_int8_w8a16:
        accumulator = (accumulator * b_scale).to(compute_type)

    offs_cn = pid_n * BLOCK_SIZE_N + tl.arange(0, BLOCK_SIZE_N)
    c_ptrs = c_ptr + stride_cm * offs_token[:, None] + stride_cn * offs_cn[None, :]
    c_mask = token_mask[:, None] & (offs_cn[None, :] < N)
    tl.store(c_ptrs, accumulator, mask=c_mask)

def invoke_fused_moe_kernel_int8(A: torch.Tensor, B: torch.Tensor, C: torch.Tensor,
                            A_scale: Optional[torch.Tensor], B_scale: Optional[torch.Tensor],
                            topk_weights: Optional[torch.Tensor], topk_ids: torch.Tensor,
                            sorted_token_ids: torch.Tensor, expert_ids: torch.Tensor,
                            num_tokens_post_padded: torch.Tensor, mul_routed_weight: bool,
                            top_k: int, compute_type: tl.dtype, use_int8_w8a16: bool,
                            per_channel_quant: bool):
    assert sorted_token_ids.stride(0) == 1
    M = A.shape[0]
    EM = sorted_token_ids.shape[0]
    triton_config = {"BLOCK_SIZE_M": 16, "BLOCK_SIZE_N": 32, "BLOCK_SIZE_K": 64,
                     "GROUP_SIZE_M": 1, "num_stages": 2, "num_warps": 2}
    grid = lambda META: (triton.cdiv(EM, META['BLOCK_SIZE_M']) * triton.cdiv(B.shape[1], META['BLOCK_SIZE_N']), )

    fused_moe_kernel[grid](
        A, B, C, A_scale, B_scale, topk_weights, sorted_token_ids, expert_ids, num_tokens_post_padded,
        B.shape[1], A.shape[1], EM, M * top_k,
        A.stride(0), A.stride(1), B.stride(0), B.stride(2), B.stride(1), C.stride(1), C.stride(2),
        A_scale.stride(0) if A_scale is not None and A_scale.ndim == 2 else 0,
        A_scale.stride(1) if A_scale is not None and A_scale.ndim == 2 else 0,
        B_scale.stride(0) if B_scale is not None and B_scale.ndim >= 2 else 0,
        B_scale.stride(2) if B_scale is not None and B_scale.ndim == 3 else 0,
        B_scale.stride(1) if B_scale is not None and B_scale.ndim >= 2 else 0,
        0, 0, MUL_ROUTED_WEIGHT=mul_routed_weight, top_k=top_k, compute_type=compute_type,
        use_fp8_w8a8=False, use_int8_w8a8=False, use_int8_w8a16=use_int8_w8a16,
        per_channel_quant=per_channel_quant, delta=1, **triton_config
    )

def perchannel_w8a16_triton(input, weight1, weight2, weight_scale1, weight_scale2,
        topk_weights, topk_ids, sorted_token_ids, expert_ids, num_tokens_post_padded, out_dtype, per_channel_quant):
    # 计算类型统一
    compute_type = tl.bfloat16 if out_dtype == torch.bfloat16 else tl.float16
    n1 = weight1.shape[1]
    top_k = topk_weights.shape[1]
    m = input.shape[0]

    output_triton = torch.zeros((m, top_k, n1), device=input.device, dtype=input.dtype)
    output_triton2 = torch.zeros((m, top_k, weight2.shape[1]), device=input.device, dtype=input.dtype)
    input_gemm2 = torch.empty((m * top_k, n1 // 2), device=input.device, dtype=input.dtype)

    # 第一层GEMM
    qinput1, qa_scale1 = moe_kernel_prepare_input(
        A=input, B=weight1, A_scale=None, B_scale=weight_scale1,
        use_fp8_w8a8=False, use_int8_w8a8=False, use_int8_w8a16=True, use_int4_w4a16=False,
        per_channel_quant=per_channel_quant, block_shape=None
    )
    invoke_fused_moe_kernel_int8(
        qinput1, weight1, output_triton, qa_scale1, weight_scale1, topk_weights, topk_ids,
        sorted_token_ids, expert_ids, num_tokens_post_padded, False, top_k, compute_type, True, per_channel_quant
    )

    # Silu激活
    aiter.moe_c_silu_and_mul(input_gemm2, output_triton.view(-1, n1))

    # 第二层GEMM
    qinput2, qa_scale2 = moe_kernel_prepare_input(
        A=input_gemm2, B=weight2, A_scale=None, B_scale=weight_scale2,
        use_fp8_w8a8=False, use_int8_w8a8=False, use_int8_w8a16=True, use_int4_w4a16=False,
        per_channel_quant=per_channel_quant, block_shape=None
    )
    invoke_fused_moe_kernel_int8(
        qinput2, weight2, output_triton2, qa_scale2, weight_scale2, topk_weights, topk_ids,
        sorted_token_ids, expert_ids, num_tokens_post_padded, True, 1, compute_type, True, per_channel_quant
    )

    # MoE Sum
    out_hidden_states = torch.empty_like(input)
    triton_moe_sum(output_triton2.view(*output_triton2.shape), out_hidden_states)
    return out_hidden_states

# ------------------- 测试类修复 -------------------
class TestW8A16BlockINT8FusedMoE(unittest.TestCase):
    # 固定为bfloat16（HCU/算子要求）
    # DTYPES = [torch.float16, torch.bfloat16]
    DTYPES = [torch.float16]
    # 测试参数
    M = [1,8,16,64,128,256,512,1024,2048,4096,8192]
    N = [768]
    K = [2048]
    BM = [16]
    E = [128]
    TOP_KS = [8]
    BLOCK_SIZE = [[]]
    SEEDS = [0]

    @classmethod
    def setUpClass(cls):
        if not torch.cuda.is_available():
            raise unittest.SkipTest("CUDA不可用")
        torch.set_default_device("cuda")
        # 固定随机种子，保证结果可复现
        torch.manual_seed(0)
        torch.cuda.manual_seed_all(0)

    def _W8A16_block_int8_fused_moe(self, M, N, K, BM, E, topk, block_size, dtype, seed):
        torch.manual_seed(seed)
        # ===================== 修复3：参数顺序修正，类型统一 =====================
        input_data, w1_marlin, w2_marlin, weight1, weight2, weight1_scale, weight2_scale, topk_weights, topk_ids = _fused_moe_helper(
            M, 2*N, K, K, N, topk, E, out_dtype=dtype, per_channel_quant=True
        )

        with torch.inference_mode():
            #  token对齐
            sorted_token_ids, expert_ids, num_tokens_post_padded = moe_align_block_size(topk_ids, 16, E, None)
            
            # 参考实现（Triton）
            triton_output = perchannel_w8a16_triton(
                input_data, weight1, weight2, weight1_scale, weight2_scale,
                topk_weights, topk_ids, sorted_token_ids, expert_ids, num_tokens_post_padded, dtype, True
            )
            
            # ===================== 修复4：移除硬编码无效参数，简化调用 =====================
            moe_output = moe_c_fused_experts(
                input_data, w1_marlin, w2_marlin, topk_weights, topk_ids,
                activation="silu",
                use_int8_w8a16=True,
                global_num_experts=E,
                w1_scale=weight1_scale,
                w2_scale=weight2_scale,
                block_shape=None,
                routed_scaling_factor=1.0
            )

        # 张量对比
        print(f"\n=== 测试用例 M={M}, E={E}, topk={topk} ===")
        compare_tensors(moe_output, triton_output, atol=1e-2, rtol=1e-2)
        print("triton_output")
        print(triton_output)
        print("moe_output")
        print(moe_output)
        
        # ===================== 修复5：合理的精度断言 =====================
        torch.testing.assert_close(moe_output, triton_output, atol=1e-2, rtol=1e-2)

# 动态生成测试用例
def generate_test_methods():
    params_list = list(itertools.product(
        TestW8A16BlockINT8FusedMoE.M,
        TestW8A16BlockINT8FusedMoE.N,
        TestW8A16BlockINT8FusedMoE.K,
        TestW8A16BlockINT8FusedMoE.BM,
        TestW8A16BlockINT8FusedMoE.E,
        TestW8A16BlockINT8FusedMoE.TOP_KS,
        TestW8A16BlockINT8FusedMoE.BLOCK_SIZE,
        TestW8A16BlockINT8FusedMoE.DTYPES,
        TestW8A16BlockINT8FusedMoE.SEEDS,
    ))
    
    for idx, params in enumerate(params_list):
        M = params[0]
        def test_method(self, params=params):
            self._W8A16_block_int8_fused_moe(*params)
        method_name = f"test_moe_M_{M}_case_{idx}"
        setattr(TestW8A16BlockINT8FusedMoE, method_name, test_method)

generate_test_methods()

if __name__ == "__main__":
    unittest.main(verbosity=2)