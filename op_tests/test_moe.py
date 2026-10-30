# SPDX-License-Identifier: MIT
# Copyright (C) 2024-2026, Advanced Micro Devices, Inc. All rights reserved.
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
import torch
from aiter.test_common import checkAllclose, perftest
from aiter import dtypes
from aiter.fused_moe import fused_moe, torch_moe, fused_topk
from aiter.fused_moe_layout import fused_moe_prepare_weights
from aiter import ActivationType, QuantType


@perftest(num_warmup=1, num_iters=2)
def torch_moe_test(
    hidden_states,
    w1,
    w2,
    topk_weight,
    topk_ids,
    # following for int8 quant
    fc1_scale=None,  # [expert, inter_dim, 1]
    fc2_scale=None,  # [expert, model_dim, 1]
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
        fc1_scale,
        fc2_scale,
        fc1_smooth_scale,
        fc2_smooth_scale,
        None,
        activation,
    )


@perftest(num_warmup=1, num_iters=2)
def fused_moe_test(
    hidden_states,
    w1,
    w2,
    topk_weight,
    topk_ids,
    activation=ActivationType.Silu,
    prepared=None,
):
    # No quantization (bf16/fp16 weights); the router inside fused_moe picks the backend
    return fused_moe(hidden_states, w1, w2, topk_weight, topk_ids,
                     activation=activation, prepared=prepared)


quant_algo = [
    "No",  # g1u0/ck(g1ux) support
    "int8quant",  # g1u1 support
    "fp8quant",  # g1u1 support
    "int8smoothquant",  # g1u1/g1u0 support
    "fp8smoothquant",  # g1u1 support
    "wint4afp8smoothquant",  # g1u1 support
]


def test_fmoe(
    dtype,
    token,
    model_dim,
    inter_dim,
    E,
    topk,
    quant="No",
    use_g1u1=False,
    shared_E=0,
    activation=ActivationType.Silu,
):
    quantAlgoId = quant_algo.index(quant)
    if quantAlgoId not in [0, 3] and not use_g1u1:
        print("g1u0 only could test no quant and int8smoothquant")
        return
    # torch.manual_seed(0)
    quantstr = quant_algo[quantAlgoId]
    use_int4 = "wint4" in quantstr
    quant_dtype = dtypes.i8 if use_int4 or quantstr.startswith("int8") else dtypes.fp8
    use_smooth = "smooth" in quantstr
    input = torch.randn((token, model_dim), dtype=dtype, device="cuda")

    if use_g1u1:
        w1 = (
            torch.randn(
                (E + shared_E, inter_dim * 2, model_dim), dtype=dtype, device="cuda"
            )
            / 10.0
        )
    else:
        w1 = torch.randn(
            (E + shared_E, inter_dim, model_dim), dtype=dtype, device="cuda"
        )
    w2 = torch.randn((E + shared_E, model_dim, inter_dim), dtype=dtype, device="cuda")
    score = torch.randn((token, E), device="cuda", dtype=dtype)
    topk_weights, topk_ids = fused_topk(input, score, topk, True)

    if shared_E > 0:
        shared_E_score = 0.5
        s_topk_weights = torch.tensor(
            [
                [shared_E_score, shared_E_score],
            ]
            * token,
            dtype=dtypes.fp32,
            device=input.device,
        )
        topk_weights = torch.cat((topk_weights, s_topk_weights), dim=1)
        s_topk_ids = torch.tensor(
            [
                [E, E + 1],
            ]
            * token,
            dtype=dtypes.i32,
            device=input.device,
        )
        topk_ids = torch.cat((topk_ids, s_topk_ids), dim=1)

    if quantAlgoId == 0:
        # ref implement
        ref2, avg_c = torch_moe_test(input, w1, w2, topk_weights, topk_ids)

        # 加载期一次性准备（决定布局 + 如需重排），前向零重排
        w1p, w2p, prepared = fused_moe_prepare_weights(
            w1, w2, quant_type=QuantType.No, dtype=dtype,
            topk=topk_ids.shape[1], activation=activation)
        print(f"[layout] quant={quantstr} layout={prepared.layout}")

        # operator under test: fused_moe (router picks the backend)
        out, avg = fused_moe_test(input, w1p, w2p, topk_weights, topk_ids,
                                  activation=activation, prepared=prepared)

        # 原始权重对拍：布局为 raw 时两者逐位一致；非 raw 时走各自路径做数值校验
        out_raw, _ = fused_moe_test(input, w1, w2, topk_weights, topk_ids,
                                    activation=activation)
        if prepared.layout == "raw":
            assert torch.equal(out, out_raw), "raw layout must be bit-exact"

        msg = f"[perf] {token=}, quant={quantstr}, {model_dim=}, {inter_dim=}, {E=}, {topk=}, dtype: {dtype}, torch_avg: {avg_c:<8.2f} us, fused_moe_avg: {avg:>8.2f} us, uplift: {avg_c/avg-1:.1%}"
        checkAllclose(ref2, out, rtol=0.01, atol=5, msg=msg)  # largest measured error: 0.26
    else:
        assert False, "quant method not support yet"


# print("test test_fmoe 16 bit")
# print("\ng1u0 no quant")
# # for dtype in [dtypes.fp16, dtypes.bf16]:
# for dtype in [dtypes.fp16]:
#     for m in [128, 256]:
#         for dim in [4096, 8192]:
#             for hdim in [1024]:
#                 # test_fmoe(dtype, m, dim, hdim, 32, 5)
#                 test_fmoe(dtype, m, dim, hdim, 32, 5, quant="No")

print("\ng1u1 no quant")
# for dtype in [dtypes.fp16, dtypes.bf16]:
for dtype in [dtypes.fp16]:
    for m in [1]:
    #for m in [1, 2, 3, 4, 5, 6, 7, 8, 9, 10, 11, 12, 13, 14, 15, 16, 17, 18, 19, 20, 21, 22, 23, 24, 25, 26, 27, 28, 29, 30, 31, 32,64,96,128,256,512,1024]:
    # for m in [1, 2,  4,  8, 16 ,32,64, 96, 128,256,512,1024,2048,4096,8192,16384,32768]:
        for dim in [7168]:
            for hdim in [256]:
                # test_fmoe(dtype, m, dim, hdim, 32, 5)
                # test_fmoe(dtype, m, dim, hdim, 256, 8, quant="No", use_g1u1=True)
                test_fmoe(dtype, m, dim, hdim, 256, 8, quant="No", use_g1u1=True)

# print("\ng1u1 int8quant")
# for dtype in [dtypes.bf16]:
#     for m in [128, 256]:
#         for dim in [4096, 8192]:
#             for hdim in [1024]:
#                 test_fmoe(
#                     dtype,
#                     m,
#                     dim,
#                     hdim,
#                     32,
#                     5,
#                     #   quant='int8quant', use_g1u1=True, shared_E=0, activation=ActivationType.Gelu)
#                     quant="int8quant",
#                     use_g1u1=True,
#                 )

# print("\ng1u1 fp8quant")
# for dtype in [dtypes.bf16]:
#     for m in [128, 256]:
#         for dim in [4096, 8192]:
#             for hdim in [1024]:
#                 test_fmoe(
#                     dtype,
#                     m,
#                     dim,
#                     hdim,
#                     32,
#                     5,
#                     quant="fp8quant",
#                     use_g1u1=True,
#                     shared_E=0,
#                     activation=ActivationType.Gelu,
#                 )
#                 #   quant='fp8quant', use_g1u1=True)


# print("\ng1u0 int8smoothquant")
# for dtype in [dtypes.bf16]:
#     for m in [128]:
#         for dim in [4096, 6144, 8192]:
#             for hdim in [512, 1024]:
#                 test_fmoe(
#                     dtype, m, dim, hdim, 32, 5, quant="int8smoothquant", use_g1u1=False
#                 )

# print("\ng1u1 int8smoothquant")
# for dtype in [dtypes.bf16]:
#     for m in [128]:
#         for dim in [4096, 6144, 8192]:
#             for hdim in [512, 1024, 1280]:
#                 test_fmoe(
#                     dtype, m, dim, hdim, 32, 5, quant="int8smoothquant", use_g1u1=True
#                 )

# print("\ng1u1 fp8smoothquant")
# for dtype in [dtypes.bf16]:
#     for m in [128]:
#         for dim in [4096, 6144, 8192]:
#             for hdim in [512, 1024, 1280]:
#                 test_fmoe(
#                     dtype, m, dim, hdim, 32, 5, quant="fp8smoothquant", use_g1u1=True
#                 )

# print("\ng1u1 int4")
# for dtype in [dtypes.bf16]:
#     for m in [32, 128]:
#         # for dim in [1024]:
#         for dim in [4096, 6144]:
#             for hdim in [1024, 4096]:
#                 test_fmoe(
#                     dtype,
#                     m,
#                     dim,
#                     hdim,
#                     8,
#                     3,
#                     quant="wint4afp8smoothquant",
#                     use_g1u1=True,
#                 )
