import torch
import itertools
from aiter.fused_moe import fused_topk, fused_moe, torch_moe
from aiter import ActivationType, dtypes
from aiter.test_common import checkAllclose, perftest, benchmark
import pandas as pd
import aiter
import os
os.environ["AMDGCN_USE_BUFFER_OPS"] = "1"
os.environ["TRITON_FUSED_MOE_CHUNK_SIZE"] = "16384"
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
    expert_mask=None,  # EP: 0/1 mask over global experts
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
        expert_mask,
        activation,
    )


@perftest(num_warmup=2, num_iters=10, testGraph=False)
def fused_moe_test(
    hidden_states,
    w1,
    w2,
    topk_weights,
    topk_ids,
    expert_mask=None,
    activation=ActivationType.Silu,
):
    # No quantization (bf16 weights); the router inside fused_moe picks the
    # backend and handles the weight layout
    return fused_moe(
        hidden_states,
        w1,
        w2,
        topk_weights,
        topk_ids,
        expert_mask=expert_mask,
        activation=activation,
    )


@benchmark()
def test_fused_moe(m: int,
                   k: int, #hidden_dim
                   n: int, #intermediate_size
                   e: int,
                   topk: int,
                   ep_size: int,
                   dtype: torch.dtype):

    torch.manual_seed(0)
    input = torch.randn((m, k), device="cuda", dtype=dtype) / 10
    w1 = torch.randn((e, 2 * n, k), device="cuda", dtype=dtype)
    w2 = torch.randn((e, k, n), device="cuda", dtype=dtype)
    score = torch.randn((m, e), device="cuda", dtype=dtype)

    if ep_size > 1:
        local_e = e // ep_size
        e_ids = torch.randint(0,
                              e, (local_e, ),
                              device="cuda",
                              dtype=torch.int32)
        # sorted so local id i == the i-th enabled global expert, matching the
        # expert_mask (0/1 over global experts) contract of fused_moe/torch_moe
        e_ids, _ = torch.sort(e_ids)
        expert_mask = torch.zeros((e, ), device="cuda", dtype=torch.int32)
        expert_mask[e_ids] = 1
        w1 = w1[e_ids]
        w2 = w2[e_ids]
    else:
        expert_mask = None


    ## 1. including token topk score calc

    ## 2. without token topk score calc
    topk_weights, topk_ids = fused_topk(input, score, topk, True)
    torch_output, avg_torch = torch_moe_test(
        input, w1, w2, topk_weights, topk_ids, expert_mask=expert_mask
    )

    #fused_moe under test
    out, avg = fused_moe_test(
        input,
        w1,
        w2,
        topk_weights,
        topk_ids,
        expert_mask=expert_mask,
        activation=ActivationType.Silu,
    )

    msg = f"[fused_moe_perf] {m=}, {k=}, {n=}, {e=}, {topk=}, dtype: {dtype}, torch_avg: {avg_torch:<8.2f} us, fused_moe_avg: {avg:>8.2f} us,uplift: {avg_torch/avg-1:.1%}"
    checkAllclose(torch_output, out, rtol=0.01, atol=1, msg=msg)
    #torch.set_printoptions(threshold=10_000)
    #print("golden",out)
    #print("out", out)
    return{
        "fused_moe_us": avg,
    }

df = []
for dtype in [dtypes.bf16]:
    for m in [1, 2, 4, 8, 16, 32, 64, 96, 128, 256, 512, 1024, 2048, 4096, 8192, 16384, 32768, 65536]:
    # for m in [4096]:
        for dim in [4096]:
            for hdim in [352]:
                ret = test_fused_moe(m, dim, hdim, 128, 8, 0, dtype)
                df.append(ret)
df = pd.DataFrame(df)
df.to_csv("moe_w16a16.csv")
aiter.logger.info(f"summary:\n{df}")
