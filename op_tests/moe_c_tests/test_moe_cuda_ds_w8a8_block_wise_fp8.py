# SPDX-License-Identifier: Apache-2.0

# Adapted from https://github.com/sgl-project/sglang/pull/3730
import itertools
import unittest

import torch

from vllm.model_executor.layers.activation import SiluAndMul
from aiter.fused_moe_c import fused_topk,moe_c_fused_experts,per_token_group_quant_fp8
import numpy as np

import torch.nn.functional as F  # 确保导入 functional

def torch_w8a8_block_fp8_moe_v2(a, w1, w2, w1_s, w2_s, topk_weight, topk_ids, topk, block_shape):
    """
    适配 N=2048 的高效 FP8 MoE 逻辑。
    优化点：减少 Python 循环内的切片操作，确保 N 维度的连续性。
    """
    B, D = a.shape
    num_experts = w1.shape[0]
    block_n, block_k = block_shape

    # 1. 准备输入：将 Token 按照 Top-k 展开
    # (B, D) -> (B * topk, D)
    a_expanded = a.view(B, 1, D).repeat(1, topk, 1).reshape(-1, D)
    topk_weight = topk_weight.view(-1)
    topk_ids = topk_ids.view(-1)

    # 2. 预先对所有展开后的 Token 进行 FP8 量化 (Per-token-group)
    a_q, a_s = native_per_token_group_quant_fp8(a_expanded, block_k)

    # 3. 创建输出缓冲区 (B*topk, N)
    N = w2.shape[1] # 这里的 N 就是 2048
    final_hidden_states = torch.zeros((B * topk, N), dtype=torch.float32, device='cuda')

    # 4. 遍历专家 (专家并行逻辑)
    for exp_id in range(num_experts):
        mask = (topk_ids == exp_id)
        if not mask.any():
            continue
            
        # 提取当前专家的 Token
        # exp_a_q = a_q[mask]  # (M_exp, D)
        # exp_a_s = a_s[mask]  # (M_exp, D // block_k)
        exp_a_q = a_q.view(torch.uint8)[mask].view(torch.float8_e4m3fn)  # (M_exp, D)
        exp_a_s = a_s[mask]  # (M_exp, D // block_k) - As 本身是 float32，可以直接索引

        # --- 第一次 FP8 矩阵乘法 (W1: Gate & Up) ---
        # 模拟 N=2048 的分块逻辑
        inter_out = optimized_block_matmul(
            exp_a_q, w1[exp_id], exp_a_s, w1_s[exp_id], block_shape
        )

        # 5. 激活函数 (SiLU Gating)
        d = inter_out.shape[-1] // 2
        # 处理可能的维度不对齐
        act_out = F.silu(inter_out[:, :d]) * inter_out[:, d:]

        # 6. 第二次 FP8 量化 (为了 W2 的输入)
        act_out_q, act_out_s = native_per_token_group_quant_fp8(act_out, block_k)

        # --- 第二次 FP8 矩阵乘法 (W2: Down) ---
        # 输出维度 N=2048 在这里体现
        exp_out = optimized_block_matmul(
            act_out_q, w2[exp_id], act_out_s, w2_s[exp_id], block_shape
        )

        final_hidden_states[mask] = exp_out

    # 7. 加权求和并返回
    # (B * topk, N) -> (B, topk, N) -> (B, N)
    out = (final_hidden_states.view(B, topk, N) * topk_weight.view(B, topk, 1)).sum(dim=1)
    return out.to(a.dtype)

def optimized_block_matmul(A, B, As, Bs, block_size):
    """
    针对 N=2048 优化的分块矩阵乘法。
    不再使用 Python List 存储 Tile，直接利用广播和向量化。
    """
    # A: (M, K) FP8, B: (N, K) FP8
    # As: (M, K//block_k), Bs: (N//block_n, K//block_k)
    M, K = A.shape
    N, _ = B.shape
    bn, bk = block_size

    # 转为 FP32 进行模拟计算（保证结果正确性，模拟硬件累加）
    A_f32 = A.to(torch.float32)
    B_f32 = B.to(torch.float32)

    # 核心逻辑：利用 Stride 模拟分块 Scale 的应用
    # 将 B 变形为 (n_tiles, bn, k_tiles, bk)
    n_tiles = N // bn
    k_tiles = K // bk
    
    # 这里的关键是：N=2048 时，n_tiles 会有 16-32 个（取决于 block_n）
    # 我们通过一次性对 B 进行 reshape 和 scale 应用来加速
    B_scaled = B_f32.view(n_tiles, bn, k_tiles, bk)
    
    # 扩充 Bs 的维度使其能与 B 广播: (n_tiles, 1, k_tiles, 1)
    Bs_expanded = Bs.view(n_tiles, 1, k_tiles, 1)
    B_scaled = B_scaled * Bs_expanded
    
    # 恢复 B 的形状: (N, K) 但已经应用了 block-wise scale
    B_final = B_scaled.reshape(N, K)

    # 对 A 应用 As (M, k_tiles, bk) * (M, k_tiles, 1)
    A_scaled = A_f32.view(M, k_tiles, bk) * As.view(M, k_tiles, 1)
    A_final = A_scaled.reshape(M, K)

    # 最终执行一个大的 GEMM，这比循环小 GEMM 快得多
    return torch.matmul(A_final, B_final.t())

def torch_w8a8_block_fp8_moe(a, w1, w2, w1_s, w2_s, score, topk, block_shape):
    """全程在GPU上执行的FP8分块量化MoE"""
    # 1. 强制所有输入张量转移到GPU
    a = a.cuda()
    w1 = w1.cuda()
    w2 = w2.cuda()
    w1_s = w1_s.cuda()
    w2_s = w2_s.cuda()
    score = score.cuda()
    
    # 处理block_shape：若为张量则转标量，确保为整数（兼容GPU张量）
    block_shape = (
        block_shape[0].item() if isinstance(block_shape[0], torch.Tensor) else block_shape[0],
        block_shape[1].item() if isinstance(block_shape[1], torch.Tensor) else block_shape[1]
    )

    B, D = a.shape
    # 2. 所有张量操作在GPU上执行
    a = a.view(B, -1, D).repeat(1, topk, 1).reshape(-1, D)
    # 显式指定GPU创建输出张量
    out = torch.zeros(B * topk, w2.shape[1], dtype=a.dtype, device='cuda')
    score = torch.softmax(score, dim=-1, dtype=torch.float32)
    # GPU上执行topk计算（无需额外指定设备，继承输入设备）
    topk_weight, topk_ids = torch.topk(score, topk)
    topk_weight = topk_weight.view(-1)
    topk_ids = topk_ids.view(-1)

    _, block_k = block_shape
    # 3. FP8量化（全程GPU）
    a_q, a_s = native_per_token_group_quant_fp8(a, block_k)  

    for i in range(w1.shape[0]):
        # GPU上计算mask（topk_ids已在GPU，无需额外转移）
        mask = topk_ids == i

        if mask.sum() > 0:
            # 4. FP8分块矩阵乘法（GPU执行）
            a_q_fp32 = a_q.to(torch.float32)  # GPU支持FP32布尔索引
            a_q_selected_fp32 = a_q_fp32[mask]
            a_q_selected = a_q_selected_fp32.to(torch.float8_e4m3fn)  # 转回FP8

            # a_s在GPU，直接索引
            a_s_selected = a_s[mask]

            inter_out = native_w8a8_block_fp8_matmul(
                a_q_selected, w1[i], a_s_selected, w1_s[i], block_shape, output_dtype=a.dtype
            )
                
            # GPU上执行激活函数（F.silu自动适配GPU）
            d = inter_out.shape[-1] // 2
            act_out = F.silu(inter_out[..., :d]) * inter_out[..., d:]
            
            # 激活输出FP8量化（GPU）
            act_out_q, act_out_s = native_per_token_group_quant_fp8(act_out, block_k)
            
            # 第二次FP8矩阵乘法（GPU）
            out[mask] = native_w8a8_block_fp8_matmul(
                act_out_q, w2[i], act_out_s, w2_s[i], block_shape, output_dtype=a.dtype
            )

    # 5. 最终结果计算（GPU）
    return (
        out.view(B, -1, w2.shape[1]) * topk_weight.view(B, -1, 1).to(out.dtype)
    ).sum(dim=1)


def native_w8a8_block_fp8_matmul(A, B, As, Bs, block_size, output_dtype=torch.float16):
    """全程在GPU上执行的FP8分块矩阵乘法"""
    # 断言所有输入张量在GPU，确保设备一致
    assert A.device.type == 'cuda', "输入A必须在GPU上"
    assert B.device.type == 'cuda', "输入B必须在GPU上"
    assert As.device.type == 'cuda', "输入As必须在GPU上"
    assert Bs.device.type == 'cuda', "输入Bs必须在GPU上"

    # FP8转float32计算（GPU上执行，利用CUDA加速）
    A = A.to(torch.float32)
    B = B.to(torch.float32)
    assert A.shape[-1] == B.shape[-1], "A's last dim must match B's last dim"
    assert B.ndim == 2 and B.is_contiguous() and Bs.ndim == 2
    assert len(block_size) == 2
    block_n, block_k = block_size[0], block_size[1]  # 已确保为整数标量
    # 验证分组数匹配
    assert (A.shape[-1] + block_k - 1) // block_k == As.shape[-1]
    assert A.shape[:-1] == As.shape[:-1]

    M = A.numel() // A.shape[-1]
    N, K = B.shape  # B在GPU，直接获取形状
    origin_C_shape = A.shape[:-1] + (N,)
    A = A.reshape(M, A.shape[-1])
    As = As.reshape(M, As.shape[-1])
    n_tiles = (N + block_n - 1) // block_n
    k_tiles = (K + block_k - 1) // block_k
    assert n_tiles == Bs.shape[0]
    assert k_tiles == Bs.shape[1]

    # 显式指定GPU创建结果张量
    C = torch.zeros((M, N), dtype=torch.float32, device='cuda')

    # 分块处理（全程GPU，张量均在GPU内存）
    A_tiles = [A[:, i * block_k : min((i + 1) * block_k, K)] for i in range(k_tiles)]
    B_tiles = [
        [
            B[
                j * block_n : min((j + 1) * block_n, N),
                i * block_k : min((i + 1) * block_k, K),
            ]
            for i in range(k_tiles)
        ]
        for j in range(n_tiles)
    ]
    C_tiles = [C[:, j * block_n : min((j + 1) * block_n, N)] for j in range(n_tiles)]
    As_tiles = [As[:, i : i + 1] for i in range(k_tiles)]

    # 分块矩阵乘法（GPU上执行，torch.matmul自动调用CUDA内核）
    for i in range(k_tiles):
        for j in range(n_tiles):
            a = A_tiles[i]
            b = B_tiles[j][i]
            c = C_tiles[j]
            s = As_tiles[i] * Bs[j][i]
            c[:, :] += torch.matmul(a, b.t()) * s  # GPU并行计算加速

    # 转换输出类型并确保在GPU
    C = C.reshape(origin_C_shape).to(output_dtype)
    return C


def native_per_token_group_quant_fp8(x, group_size, eps=1e-10, dtype=torch.float8_e4m3fn):
    """全程在GPU上执行的FP8逐token分组量化"""
    # 修正原代码断言错误：将cuda改为cuda，确保输入在GPU
    assert x.device.type == 'cuda', "输入x必须在GPU上"
    assert (
        x.shape[-1] % group_size == 0
    ), "the last dimension of `x` must be divisible by `group_size`"
    assert x.is_contiguous(), "`x` must be contiguous"

    # 获取FP8格式元信息（与设备无关）
    finfo = torch.finfo(dtype)
    fp8_max = finfo.max
    fp8_min = finfo.min

    # 分组与量化计算（全程GPU，利用CUDA并行加速）
    x_ = x.reshape(x.numel() // group_size, group_size)
    amax = x_.abs().max(dim=-1, keepdim=True)[0].clamp(min=eps).to(torch.float32)
    x_s = amax / fp8_max
    x_q = (x_ / x_s).clamp(min=fp8_min, max=fp8_max).to(dtype)

    # 恢复原形状（GPU上执行，张量不脱离GPU内存）
    x_q = x_q.reshape(x.shape)
    x_s = x_s.reshape(x.shape[:-1] + (x.shape[-1] // group_size,))

    return x_q, x_s

# For test
def native_per_token_group_quant_int8(x, group_size, eps=1e-10, dtype=torch.int8):
    """per-token-group quantization on an input tensor `x` using native torch.

    It converts the tensor values into float8 values and returns the
    quantized tensor along with the scaling factor used for quantization.
    Note that only `torch.float8_e4m3fn` is supported for now.
    """
    assert (
        x.shape[-1] % group_size == 0
    ), "the last dimension of `x` cannot be divisible by `group_size`"
    assert x.is_contiguous(), "`x` is not contiguous"

    iinfo = torch.iinfo(dtype)
    int8_min = iinfo.min
    int8_max = iinfo.max

    x_ = x.reshape(x.numel() // group_size, group_size)
    amax = x_.abs().max(dim=-1, keepdim=True)[0].clamp(min=eps).to(torch.float32)
    x_s = amax / int8_max
    x_q = (x_ / x_s).clamp(min=int8_min, max=int8_max).to(dtype)
    x_q = x_q.reshape(x.shape)
    x_s = x_s.reshape(x.shape[:-1] + (x.shape[-1] // group_size,))

    return x_q, x_s


# For test
def native_w8a8_block_int8_matmul(A, B, As, Bs, block_size, output_dtype=torch.float16):
    """matrix multiplication with block-wise quantization using native torch.

    It takes two input tensors `A` and `B` with scales `As` and `Bs`.
    The output is returned in the specified `output_dtype`.
    """

    A = A.to(torch.float32)
    B = B.to(torch.float32)
    assert A.shape[-1] == B.shape[-1]
    assert B.ndim == 2 and B.is_contiguous() and Bs.ndim == 2
    assert len(block_size) == 2
    block_n, block_k = block_size[0], block_size[1]
    assert (A.shape[-1] + block_k - 1) // block_k == As.shape[-1]
    assert A.shape[:-1] == As.shape[:-1]

    M = A.numel() // A.shape[-1]
    N, K = B.shape
    origin_C_shape = A.shape[:-1] + (N,)
    A = A.reshape(M, A.shape[-1])
    As = As.reshape(M, As.shape[-1])
    n_tiles = (N + block_n - 1) // block_n
    k_tiles = (K + block_k - 1) // block_k
    assert n_tiles == Bs.shape[0]
    assert k_tiles == Bs.shape[1]

    C_shape = (M, N)
    C = torch.zeros(C_shape, dtype=torch.float32, device=A.device)

    A_tiles = [A[:, i * block_k : min((i + 1) * block_k, K)] for i in range(k_tiles)]
    B_tiles = [
        [
            B[
                j * block_n : min((j + 1) * block_n, N),
                i * block_k : min((i + 1) * block_k, K),
            ]
            for i in range(k_tiles)
        ]
        for j in range(n_tiles)
    ]
    C_tiles = [C[:, j * block_n : min((j + 1) * block_n, N)] for j in range(n_tiles)]
    As_tiles = [As[:, i : i + 1] for i in range(k_tiles)]

    for i in range(k_tiles):
        for j in range(n_tiles):
            a = A_tiles[i]
            b = B_tiles[j][i]
            c = C_tiles[j]
            s = As_tiles[i] * Bs[j][i]
            c[:, :] += torch.matmul(a, b.t()) * s

    C = C.reshape(origin_C_shape).to(output_dtype)
    return C


# For test
def torch_w8a8_block_int8_moe(a, w1, w2, w1_s, w2_s, score, topk, block_shape):
    """fused moe with block-wise quantization using native torch."""

    B, D = a.shape
    a = a.view(B, -1, D).repeat(1, topk, 1).reshape(-1, D)
    out = torch.zeros(B * topk, w2.shape[1], dtype=a.dtype, device=a.device)
    score = torch.softmax(score, dim=-1, dtype=torch.float32)
    topk_weight, topk_ids = torch.topk(score, topk)
    topk_weight = topk_weight.view(-1)
    topk_ids = topk_ids.view(-1)

    _, block_k = block_shape[0], block_shape[1]
    a_q, a_s = native_per_token_group_quant_int8(a, block_k)  
    for i in range(w1.shape[0]):
        mask = topk_ids == i
        if mask.sum():
            # if i == 0:
            #     print(f"=================================a_q[mask] shape is = {a_q[mask].shape}")
            #     for j in range(10):
            #         print(f"a_q[mask]={a_q[mask][0][j]}")
            # print(f"=================================w1[0] shape is = {w1[i].shape}")
            # for j in range(256):
            #     print(f"w1[i]={w1[i][0][j]}")
            #     print(f"=================================a_s[mask] shape is = {a_s[mask].shape}")
            #     for j in range(128):
            #         print(f"a_s[mask]={a_s[mask][j]}")
            #     print(f"=================================w1_s[0] shape is = {w1_s[i].shape}")
            #     for j in range(2):
            #         print(f"w1_s[0] ={w1_s[i][j]}")


            inter_out = native_w8a8_block_int8_matmul(
                a_q[mask], w1[i], a_s[mask], w1_s[i], block_shape, output_dtype=a.dtype
            )
            # print(f"==============inter_out shape is = {inter_out.shape}")
            # for j in range(10):
            #     print(f"torch result[{j}]={inter_out[0][j]}")
                
            act_out = SiluAndMul().forward_native(inter_out)
            act_out_q, act_out_s = native_per_token_group_quant_int8(act_out, block_k)
            act_out = act_out.to(torch.float32)
            out[mask] = native_w8a8_block_int8_matmul(
                act_out_q, w2[i], act_out_s, w2_s[i], block_shape, output_dtype=a.dtype
            )
    return (
        out.view(B, -1, w2.shape[1]) * topk_weight.view(B, -1, 1).to(out.dtype)
    ).sum(dim=1)




class TestW8A8BlockINT8FusedMoE(unittest.TestCase):
    DTYPES = [torch.bfloat16]
    M = [1,2,4,5,6,7,8,9,10,11,12,13,14,15,16,32,64,128,256,512,1024,1024,2048,4096,8192,16384,32768]
    # M = [1,2,4,5,6,7,8,9,10,11,12,13,14,15,16,32,64,128,256,512,1024]
    # M = [1]
    N = [4096]
    K = [7168]
    # K = [512]
    BM = [16]
    BN = [64]
    BK = [128]
    kloops = [1]
    nloops = [4]
    BN2 = [64]
    BK2 = [128]
    kloops2 = [1]
    nloops2 = [4]
    E = [256]
    TOP_KS = [8]
    # TOP_KS = [1]

    BLOCK_SIZE = [[128,128]]
    SEEDS = [0]

    @classmethod
    def setUpClass(cls):
        if not torch.cuda.is_available():
            raise unittest.SkipTest("CUDA is not available")
        torch.set_default_device("cuda")

    def _w8a8_block_int8_fused_moe(self, M, N, K, BM,BN,BK,kloops,nloops,BN2,BK2,kloops2,nloops2,E, topk, block_size, dtype, seed):
        
        torch.manual_seed(seed)
        factor_for_scale = 1e-2

        finfo = torch.finfo(torch.float8_e4m3fn)
        fp8_min = finfo.min
        fp8_max = finfo.max
        int8_min = -127
        int8_max = 127
        # a = torch.arange(1,M+1,device = "cuda",dtype = dtype) 
        # a = a.unsqueeze(1)
        # a = a.repeat(1,K)
        a = torch.randn((M, K), device="cuda", dtype=dtype) 
        #assert(a.stride()[1] == 1) 
        
        #forward = torch.arange(1, K+1, device="cuda", dtype=dtype)/10  # 1-128
        #backward = torch.arange(K, 0, -1, device="cuda", dtype=dtype)/10  # 128-1

        # 初始化结果张量 (M, K)
        #a = torch.empty((M, K), device="cuda", dtype=dtype)

        # 通过for循环逐行填充
        #for i in range(M):
        #    if i % 2 == 0:  # 偶数索引（0、2、4...）对应奇数行，填充1-128
        #        a[i] = forward
        #    else:  # 奇数索引（1、3、5...）对应偶数行，填充128-1
        #        a[i] = forward

        # w1_fp32 = torch.arange(1, K+1, device="cuda", dtype=torch.float32) 

        # # 2. 扩展为 (1, 1, K)（在第0、1维度插入新维度）
        # w1_fp32 = w1_fp32.unsqueeze(0).unsqueeze(0)  # 先 unsqueeze(0) 得到 (1, K)，再 unsqueeze(0) 得到 (1, 1, K)

        # # 3. 按 (E, 2*N, 1) 重复：第0维重复E次，第1维重复2*N次，第2维不重复
        # w1_fp32 = w1_fp32.repeat(E, 2*N, 1)

        # 各行之间不同 行内所有数值一样为所在行行序号
        # row_indices = torch.arange(2*N, device="cuda", dtype=torch.float32) 
        # w1_per_expert = row_indices.unsqueeze(1).repeat(1, K)
        # w1_fp32 = w1_per_expert.unsqueeze(0).repeat(E, 1, 1)
        # print("整体是否连续:", w1_fp32.is_contiguous()) 
        # print("各维度步长:", w1_fp32.stride())  # 输出 (2*N*K, K, 1)
        w1_fp32 = (torch.rand((E, 2 * N, K), device="cuda", dtype=torch.float32) - 0.5) * 2 * int8_max
        w1 = w1_fp32.clamp(min=int8_min, max=int8_max).to(torch.int8)
        w1_fp8 = w1.to(torch.float8_e4m3fn)
        
        
        # w2_fp32 = torch.arange(1, N+1, device="cuda", dtype=torch.float32) 

        # # 2. 扩展为 (1, 1, K)（在第0、1维度插入新维度）
        # w2_fp32 = w2_fp32.unsqueeze(0).unsqueeze(0)  # 先 unsqueeze(0) 得到 (1, K)，再 unsqueeze(0) 得到 (1, 1, K)

        # # 3. 按 (E, 2*N, 1) 重复：第0维重复E次，第1维重复2*N次，第2维不重复
        # w2_fp32 = w2_fp32.repeat(E, K, 1)


        w2_fp32 = (torch.rand((E, K, N), device="cuda", dtype=torch.float32) - 0.5) * 2 * int8_max 
        w2 = w2_fp32.clamp(min=int8_min, max=int8_max).to(torch.int8)
        w2_fp8 = w2.to(torch.float8_e4m3fn)

        block_n, block_k = block_size[0], block_size[1]
        n_tiles_w1 = (2 * N + block_n - 1) // block_n
        n_tiles_w2 = (K + block_n - 1) // block_n
        k_tiles_w1 = (K + block_k - 1) // block_k
        k_tiles_w2 = (N + block_k - 1) // block_k
        
        
        w1_s_cuda = torch.rand((E, n_tiles_w1, k_tiles_w1), dtype=torch.float32) * factor_for_scale
        w2_s_cuda = torch.rand((E, n_tiles_w2, k_tiles_w2), dtype=torch.float32) * factor_for_scale

        score = torch.rand((M, E), dtype=dtype)
        # data = torch.load('/home/zhouxulang/Moe_w8a8_opt_single_test_v5_fp8/data.pt')

        # a = data['a']
        # w1 = data["w1"]
        # w1_fp8 = w1.to(torch.float8_e4m3fn)
        # w2 = data["w2"]
        # w2_fp8 = w2.to(torch.float8_e4m3fn)
        # score = data['score']
        # w1_s_cuda = data['w1_s_cuda']
        # w2_s_cuda = data['w2_s_cuda']

        # print("w1")
        # print(w1[1:10].cpu().tolist())
        # print("w1")
        # print(w1_fp8[1:10].cpu().tolist())
        # print("topk**********************")
        # print(topk)
        topk_weights, topk_ids = fused_topk(a, score, topk, False)
        # a_q, a_scale = per_token_group_quant_fp8(a, block_k)

        with torch.inference_mode():
            
            out = moe_c_fused_experts(
                a, w1_fp8, w2_fp8,topk_weights, topk_ids,
                use_fp8_w8a8 = True,
                global_num_experts=E,
                w1_scale=w1_s_cuda,
                w2_scale=w2_s_cuda,
                block_shape=block_size
            )
            # ref_out = fused_moe(
            #     a, w1, w2, w1,score, topk,
            #     renormalize=False,
            #     use_int8_w8a16=True,
            #     global_num_experts=E,
            #     w1_scale=w1_s_cuda,
            #     w2_scale=w2_s_cuda,
            #     block_shape=block_size,
            #     BM = BM,BN = BN,BK =BK,kloops= kloops, nloops = nloops,
            #     BN2 = BN2,BK2 =BK2,kloops2= kloops2, nloops2 = nloops2
            # )
            # ref_out = torch_w8a8_block_fp8_moe(
            #     a, w1_fp8, w2_fp8, w1_s_cuda, w2_s_cuda, score, topk, block_size
            # )
            ref_out = torch_w8a8_block_fp8_moe_v2(a, w1_fp8, w2_fp8, w1_s_cuda, w2_s_cuda, topk_weights, topk_ids,topk, block_size)
        # print("===========================================================dtype")
        # print(out.dtype)
        # print(ref_out.dtype)
        
        
        print(f"M={M}: Triton has NaN={torch.isnan(out.cpu()).any().item()}\n PyTorch has NaN={torch.isnan(ref_out.cpu()).any().item()}")
        
        out_flat = out.flatten()[:100]
        ref_out_flat = ref_out.flatten()[:100]
        for i in range(100):
            print(f"out_flat[{i}]={out_flat[i]} vs ref_out_flat[{i}]={ref_out_flat[i]}")

        # torch.testing.assert_close(out, ref_out, atol=2e-1, rtol=0) 
        
        self.assertTrue(
            torch.mean(torch.abs(out.to(torch.float32) - ref_out.to(torch.float32)))
            / torch.mean(torch.abs(ref_out.to(torch.float32)))
            < 0.02
            # < 0.1
        )
        # # count_relative_differences(out, ref_out, rel_threshold=0.1, abs_threshold=1e-1, print_errors=True)
        
      
            

# 动态为每个参数组合生成独立的测试方法
def generate_test_methods():
    # 将参数组合转换为列表（可索引访问）
    params_list = list(itertools.product(
        TestW8A8BlockINT8FusedMoE.M,
        TestW8A8BlockINT8FusedMoE.N,
        TestW8A8BlockINT8FusedMoE.K,
        TestW8A8BlockINT8FusedMoE.BM,
        TestW8A8BlockINT8FusedMoE.BN,
        TestW8A8BlockINT8FusedMoE.BK,
        TestW8A8BlockINT8FusedMoE.kloops,
        TestW8A8BlockINT8FusedMoE.nloops,
        TestW8A8BlockINT8FusedMoE.BN2,
        TestW8A8BlockINT8FusedMoE.BK2,
        TestW8A8BlockINT8FusedMoE.kloops2,
        TestW8A8BlockINT8FusedMoE.nloops2,
        TestW8A8BlockINT8FusedMoE.E,
        TestW8A8BlockINT8FusedMoE.TOP_KS,
        TestW8A8BlockINT8FusedMoE.BLOCK_SIZE,
        TestW8A8BlockINT8FusedMoE.DTYPES,
        TestW8A8BlockINT8FusedMoE.SEEDS,
    ))

    
    for idx, params in enumerate(params_list):
        M = params[0]  # 用M值作为方法名的一部分
        
        # 定义测试方法（闭包，绑定当前参数）
        def test_method(self, params=params):
            self._w8a8_block_int8_fused_moe(*params)
        
        # 方法名必须以test_开头，unittest才会识别为测试方法
        method_name = f"test_moe_M_{M}_case_{idx}"
        
        # 将方法绑定到测试类
        setattr(TestW8A8BlockINT8FusedMoE, method_name, test_method)


# 调用函数生成所有测试方法
generate_test_methods()
    
        
        
            
        


if __name__ == "__main__":
    unittest.main(verbosity=0)
