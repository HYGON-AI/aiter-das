# Copyright (c) 2024, Advanced Micro Devices, Inc. All rights reserved.
# SPDX-License-Identifier: MIT
import torch
import itertools
import aiter
from aiter import dtypes
from aiter.test_common import (
    checkAllclose,
    benchmark,
    run_perftest,
)

from aiter.fused_moe import (
    fused_topk,
    fused_moe,
    torch_moe_stage1,
    torch_moe_stage2,
)


from aiter import ActivationType

torch.int4 = getattr(torch, "int4", torch.uint32)
torch.set_default_device("cuda")


@benchmark()
def test_fmoe(
    dtype,
    token,
    model_dim,
    inter_dim,
    E,
    topk,
    actType,
    qType,
    AQDType,
    WQDType,
    use_g1u1=False,
    doweight_stage1=False,
):
    torch_quant = aiter.get_torch_quant(qType)
    torch_act = aiter.get_torch_act(actType)
    input = torch.randn((token, model_dim), dtype=dtype) / 10  # scaled like the EP and w16a16 tests
    # Scale the weights down: unscaled randn weights give outputs of ~1e5-1e6,
    # where bf16 rounding alone exceeds any elementwise atol. Use the same
    # tolerance as test_moe_ep (rtol=0.01, atol=10).
    if use_g1u1:
        w1 = torch.randn((E, inter_dim * 2, model_dim), dtype=dtype) / 10
    else:
        w1 = torch.randn((E, inter_dim, model_dim), dtype=dtype) / 10
    w2 = torch.randn((E, model_dim, inter_dim), dtype=dtype) / 10

    score = torch.randn((token, E), dtype=dtype)
    topk_weights, topk_ids = fused_topk(input, score, topk, True)

    if qType == aiter.QuantType.per_Tensor:
        # per-expert weight scale, (E, 1); fused_moe broadcasts it internally
        w1_qt, w1_scale = aiter.pertoken_quant(w1.view(E, -1), quant_dtype=WQDType)
        w2_qt, w2_scale = aiter.pertoken_quant(w2.view(E, -1), quant_dtype=WQDType)
    elif qType == aiter.QuantType.per_Token and WQDType == torch.int4:  # int4 w quant
        w1_qt, w1_scale = aiter.pertoken_quant(w1, quant_dtype=dtypes.i8, dtypeMax=7)
        w2_qt, w2_scale = aiter.pertoken_quant(w2, quant_dtype=dtypes.i8, dtypeMax=7)
    else:
        w1_qt, w1_scale = torch_quant(w1, quant_dtype=WQDType)
        w2_qt, w2_scale = torch_quant(w2, quant_dtype=WQDType)

    # fused_moe handles the kernel-side weight layout internally; keep the
    # natural (E, N, K) container for both the ref and the operator
    w1_qt = w1_qt.view(w1.shape)
    w2_qt = w2_qt.view(w2.shape)

    a1_qt, a1_scale = torch_quant(input, quant_dtype=AQDType)
    # w1_scale = w1_scale.fill_(1)
    # a1_scale = a1_scale.fill_(1)

    # ######################## ref stage 1 (feeds the stage 2 ref) ###########
    out1_ref, us_ref = run_perftest(
        torch_moe_stage1,
        a1_qt,
        w1_qt,
        w2_qt,
        topk_weights,
        topk_ids,
        dtype=dtype,
        activation=actType,
        quant_type=qType,
        a1_scale=a1_scale,
        w1_scale=w1_scale,
        num_iters=3,
        doweight=doweight_stage1,
    )

    # ######################## ref stage 2 ###########
    if qType == aiter.QuantType.per_Token:
        out1_ref = out1_ref.view(token, -1)
    a2_qt, a2_scale = torch_quant(out1_ref, quant_dtype=AQDType)
    # a2_scale = a2_scale.fill_(1)
    out2_ref, us_ref = run_perftest(
        torch_moe_stage2,
        a2_qt,
        w1_qt,  # E, inter_dim*2, model_dim
        w2_qt,  # E, model_dim, inter_dim
        topk_weights,
        topk_ids,
        dtype=dtype,
        quant_type=qType,
        w2_scale=w2_scale,
        a2_scale=a2_scale,
        num_iters=3,
        doweight=not doweight_stage1,
    )

    # ######################## fused_moe (all stages) ###########
    # fused_moe does not support doweight_stage1=True, so the list below only
    # contains False.
    out2_aiter, us_fuse = run_perftest(
        fused_moe,
        input,
        w1_qt,
        w2_qt,
        topk_weights,
        topk_ids,
        w1_scale=w1_scale,
        w2_scale=w2_scale,
        quant_type=qType,
        activation=actType,
        doweight_stage1=doweight_stage1,
    )

    err = checkAllclose(
        out2_ref,
        out2_aiter,
        rtol=0.01,
        atol=10,  # same band as test_moe_ep
        msg=f"fused_moe_all_stages:{us_fuse:>8.2f} us......",
    )

    return {"us": us_fuse, "err": err}


list_dtype = [dtypes.bf16, dtypes.fp16][:1]
list_tokenNum = [
    1,
    3,
    5,
    16,
    32,
    64,
    128,
    256,
    1024,
    4096,
    163840,
]
# Two shape groups:
#  * small toy shapes (E=8/topk=2) with no tuned config. They run on the triton
#    default-config fallback and log one warning per shape. Full token sweep.
#  * a production-like group (E=256/topk=8/K=7168/N=128) with tuned asm rows.
#    Short token list to bound runtime.
list_configs = [
    dict(expert=8, topk=2, model_dim=6144, inter_dim=4096,
         tokens=list_tokenNum),
    dict(expert=256, topk=8, model_dim=7168, inter_dim=128,
         tokens=[1, 16, 64, 256, 1024]),
]
list_quant = [
    (aiter.QuantType.No, None, None),  # a16w16
    (aiter.QuantType.per_Tensor, dtypes.fp8, dtypes.fp8),  # a8w8
    (aiter.QuantType.per_Token, dtypes.fp8, dtypes.fp8),  # a8w8
    # a8w4 (int4 weights) is not covered because fused_moe does not support it:
    # (aiter.QuantType.per_Token, dtypes.fp8, torch.int4),
    # (aiter.QuantType.per_128x128, dtypes.fp8, dtypes.fp8),  # a8w8 TODO add test
]
list_act = [aiter.ActivationType.Silu, aiter.ActivationType.Gelu][:]
list_doweight_stage1 = [False][:]  # fused_moe raises for doweight_stage1=True

import pandas as pd

for (
    dtype,
    act_type,
    (quant_type, aq_dtype, wq_dtype),
    cfg,
    doweight_stage1,
) in itertools.product(
    list_dtype, list_act, list_quant, list_configs, list_doweight_stage1
):
    df = []
    for m in cfg["tokens"]:
        ret = test_fmoe(
            dtype,
            m,
            cfg["model_dim"],
            cfg["inter_dim"],
            cfg["expert"],
            cfg["topk"],
            act_type,
            quant_type,
            aq_dtype,
            wq_dtype,
            use_g1u1=True,
            doweight_stage1=doweight_stage1,
        )
        df.append(ret)
    df = pd.DataFrame(df)
    aiter.logger.info(f"summary:\n{df}")
