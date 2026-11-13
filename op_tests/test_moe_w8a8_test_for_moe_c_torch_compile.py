import pytest
import torch
import itertools

from op_tests.utility.scalar_type import ScalarType, scalar_types
from op_tests.utility.utils import quantize_weights
from op_tests.utility.utils import torch_moe as torch_score_moe
from aiter.fused_moe import fused_moe, fused_topk, torch_moe
from aiter.fused_moe_layout import fused_moe_prepare_weights
from aiter import ActivationType, QuantType
from aiter.test_common import checkAllclose, perftest,benchmark
from aiter import dtypes
import pandas as pd
import aiter
import os
os.environ["AMDGCN_USE_BUFFER_OPS"] = "1"
#Notice: Adjust benchmark block_size_m here
BLOCK_SIZE_M_CK = 16
torch.set_printoptions(profile="full")  # 完整打印


@perftest(num_warmup=1, num_iters=2)
def torch_moe_test(
    hidden_states,
    w1,
    w2,
    topk_weight,
    topk_ids,
    # following for int8 quant
    w1_scale=None,  # [expert, inter_dim, 1]
    w2_scale=None,  # [expert, model_dim, 1]
    fc1_smooth_scale=None,  # [expert, 1, model_dim]
    fc2_smooth_scale=None,  # [expert, 1, inter_dim]
    activation=ActivationType.Silu,
):
    return torch_moe(
        hidden_states,
        w1,
        w2,
        topk_weight,
        topk_ids,
        w1_scale,
        w2_scale,
        fc1_smooth_scale,
        fc2_smooth_scale,
        None,
        activation,
    )


@perftest(num_warmup=5, num_iters=10, testGraph=False)
def fused_moe_impl(hidden_states, w1, w2, topk_weights, topk_ids,
                   dtype=None, expert_mask=None, prepared=None):
    # per-channel int8 w8a8: QuantType.per_Token with the [E, N, 1] / [E, K, 1] scales
    return fused_moe(
        hidden_states,
        w1,
        w2,
        topk_weights,
        topk_ids,
        expert_mask=expert_mask,
        quant_type=QuantType.per_Token,
        dtype=dtype,
        prepared=prepared,
    )


@perftest()
def torchcompile_fused_moe_impl(hidden_states, w1, w2, topk_weights, topk_ids,
                                dtype=None, expert_mask=None,
                                prepared=None):
    fn = torch.compile(fused_moe, backend="inductor", fullgraph=True)
    return fn(
        hidden_states,
        w1,
        w2,
        topk_weights,
        topk_ids,
        expert_mask=expert_mask,
        quant_type=QuantType.per_Token,
        dtype=dtype,
        prepared=prepared,
    )


@benchmark()
def test_fused_moe_w8a8(m: int,
                        k: int, #hidden_dim
                        n: int, #intermediate_size
                        e: int,
                        topk: int,
                        ep_size: int,
                        dtype: torch.dtype,
                        weight_bits: int):
    input = torch.randn((m, k), device="cuda", dtype=dtype) / 10
    w1 = torch.randn((e, 2 * n, k), device="cuda", dtype=dtype)
    w2 = torch.randn((e, k, n), device="cuda", dtype=dtype)
    score = torch.randn((m, e), device="cuda", dtype=dtype)

    w1_ref = w1.clone()
    w2_ref = w2.clone()

    max_vals = torch.abs(w1.to(torch.float32)).max(dim=-1, keepdim=True)[0]
    #max_vals = torch.abs(w1).max(dim=-1, keepdim=True)[0]
    max_vals = max_vals.clamp(min=1e-5)
    w1_scales = max_vals / 127.0
    w1_qweight = (w1 / max_vals * 127.0).round().clamp(min=-128, max=127).to(torch.int8)

    max_vals = torch.abs(w2.to(torch.float32)).max(dim=-1, keepdim=True)[0]
    #max_vals = torch.abs(w2).max(dim=-1, keepdim=True)[0]
    max_vals = max_vals.clamp(min=1e-5)
    w2_scales = max_vals / 127.0
    w2_qweight = (w2 / max_vals * 127.0).round().clamp(min=-128, max=127).to(torch.int8)

    if ep_size > 1:
        local_e = e // ep_size
        e_ids = torch.randint(0,
                              e, (local_e, ),
                              device="cuda",
                              dtype=torch.int32)
        # fused_moe takes a 0/1 mask over global experts and converts it to an expert map
        e_map = torch.zeros((e, ), device="cuda", dtype=torch.int32)
        e_map[e_ids] = 1
        w1_ref = w1_ref[e_ids]
        w2_ref = w2_ref[e_ids]
        w1_qweight = w1_qweight[e_ids]
        w2_qweight = w2_qweight[e_ids]
        w1_scales = w1_scales[e_ids]
        w2_scales = w2_scales[e_ids]
    else:
        e_map = None


    ## 1. including token topk score calc

    ## 2. without token topk score calc
    topk_weights, topk_ids = fused_topk(input, score, topk, True)

    # debug purpose
    """
    print("###### topk_weights dtype = {}, shape = {}".format(topk_weights.dtype, topk_weights.shape))
    print("###### topk_ids dtype = {}, shape = {}".format(topk_ids.dtype, topk_ids.shape))
    print("###### w1_qweight dtype = {}, shape = {}".format(w1_qweight.dtype, w1_qweight.shape))
    print("###### w2_qweight dtype = {}, shape = {}".format(w2_qweight.dtype, w2_qweight.shape))
    print("###### w1_scales dtype = {}, shape = {}".format(w1_scales.dtype, w1_scales.shape))
    print("###### w2_scales dtype = {}, shape = {}".format(w2_scales.dtype, w2_scales.shape))
    print("###### w1_qzeros dtype = {}, shape = {}".format(w1_qzeros.dtype if has_zp else None, w1_qzeros.shape if has_zp else None))
    print("###### w2_qzeros dtype = {}, shape = {}".format(w2_qzeros.dtype if has_zp else None, w2_qzeros.shape if has_zp else None))
    print("###### w1_ref dtype = {}, shape = {}".format(w1_ref.dtype, w1_ref.shape))
    print("###### w2_ref dtype = {}, shape = {}".format(w2_ref.dtype, w2_ref.shape))
    """

    torch_output, avg_torch = torch_moe_test(input, w1_ref, w2_ref, topk_weights, topk_ids)


    #Triton Solution
    # 加载期一次性准备（布局决策 + 如需重排），前向零重排
    w1_prep, w2_prep, prepared = fused_moe_prepare_weights(
        w1_qweight, w2_qweight, quant_type=QuantType.per_Token,
        w1_scale=w1_scales, w2_scale=w2_scales, dtype=dtype,
        topk=topk_ids.shape[1],
        activation=ActivationType.Silu, expert_mask=e_map)
    triton_output, avg_triton = fused_moe_impl(
        input,
        w1_prep,
        w2_prep,
        topk_weights,
        topk_ids,
        dtype=dtype,
        expert_mask=e_map,
        prepared=prepared)

    # fused_moe shuffles the weight layout internally
    c_output, avg_c = torchcompile_fused_moe_impl(
        input,
        w1_prep,
        w2_prep,
        topk_weights,
        topk_ids,
        dtype=dtype,
        expert_mask=e_map,
        prepared=prepared)

    msg = f"[TRITON_perf] {m=}, {k=}, {n=}, {e=}, {topk=}, dtype: {dtype}, torch_avg: {avg_torch:<8.2f} us, triton_avg: {avg_triton:>8.2f} us,uplift: {avg_torch/avg_triton-1:.1%}"
    checkAllclose(torch_output, triton_output, rtol=0.01, atol=30, msg=msg)  # largest measured error: 14.0

    msg = f"[C_perf] {m=}, {k=}, {n=}, {e=}, {topk=}, dtype: {dtype}, torch_avg: {avg_torch:<8.2f} us, c_avg: {avg_c:>8.2f} us,uplift: {avg_torch/avg_c-1:.1%}"
    checkAllclose(torch_output, c_output, rtol=0.01, atol=30, msg=msg)  # largest measured error: 14.0


    return{
        "triton_us": avg_triton,
        "asm_us": 1,
        "c_us": avg_c
    }



df = []
for dtype in [dtypes.bf16]:
    # for m in [22]:
    for m in [1]:
    # for m in [1, 2,  4,  8, 16 ,32,64, 96, 128,256,512,1024,2048,4096,8192,16384,32768]:
        for dim in [7168]:
            for hdim in [128]:
                # test_fmoe(dtype, m, dim, hdim, 32, 5)
                # test_fmoe(dtype, m, dim, hdim, 256, 8, quant="No", use_g1u1=True)
                ret = test_fused_moe_w8a8(m, dim, hdim, 256, 8, 0, dtype, 8)
                df.append(ret)
df = pd.DataFrame(df)
df.to_csv("moe_w8a8_perToken_int8.csv")
aiter.logger.info(f"summary:\n{df}")
