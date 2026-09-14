# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
# SPDX-License-Identifier: MIT
"""两个后端共享的数据准备、精度检查与性能测量。

构造可复现的量化权重、scale/zero point、路由和 Torch reference；
封装公开 aiter_moe 调用及 eager/Graph 计时。"""
import math
import statistics

import torch
import torch.nn.functional as F


def torch_dtype(spec):
    return torch.float16 if spec.dtype == "fp16" else torch.bfloat16


def make_data(spec, m):
    torch.manual_seed(spec.seed)
    dtype = torch_dtype(spec)
    e, n, k = spec.experts, spec.inter_dim, spec.model_dim
    x = torch.randn((m, k), device="cuda", dtype=dtype) / 100
    w1 = torch.randn((e, 2 * n, k), device="cuda", dtype=dtype)
    w2 = torch.randn((e, k, n), device="cuda", dtype=dtype)
    score = torch.randn((m, e), device="cuda", dtype=dtype)
    weights, ids = score.float().softmax(-1).topk(spec.topk, dim=-1)
    weights = (weights / weights.sum(-1, keepdim=True)).contiguous()
    ids = ids.to(torch.int32).contiguous()
    scales, zeros, refs = [None, None], [None, None], [w1, w2]
    quantized = []
    for i, weight in enumerate((w1, w2)):
        if spec.quant_type == "no_quant":
            q = weight
        elif spec.quant_type in ("int8_w8a8_channel", 'int8_w8a16'):
            maximum = weight.float().abs().amax(-1, keepdim=True).clamp_min(1e-5)
            scales[i] = maximum / 127
            q = (weight / maximum * 127).round().clamp(-128, 127).to(torch.int8)
            if spec.quant_type == 'int8_w8a16':
                refs[i] = (q.float() * scales[i]).to(dtype)
        elif spec.quant_type in ('int8_w8a8_block', 'f8_w8a8_block'):
            bn, bk = spec.block_shape
            blocks = weight.float().reshape(e, weight.shape[1] // bn, bn, weight.shape[2] // bk, bk)
            fp8 = spec.quant_type.startswith('f8')
            from aiter import dtypes
            if fp8 and dtypes.fp8 == torch.uint8:
                raise RuntimeError('FP8 is unavailable on this device')
            qdtype = dtypes.fp8 if fp8 else torch.int8
            qmax = torch.finfo(qdtype).max if fp8 else 127
            scales[i] = blocks.abs().amax((2, 4)).clamp_min(1e-5) / qmax
            expanded = scales[i][:, :, None, :, None]
            values = blocks / expanded
            if not fp8:
                values = values.round()
            q = values.clamp(-qmax, qmax).to(qdtype).reshape_as(weight).contiguous()
            refs[i] = (q.float().reshape_as(blocks) * expanded).reshape_as(weight).to(dtype)
        elif spec.quant_type in ('int4_w4a16', 'int4_w4a8'):
            blocks = weight.float().reshape(e, weight.shape[1], -1, spec.q_size_k)
            if spec.has_zp:
                low, high = blocks.amin(-1), blocks.amax(-1)
                scale = ((high - low).clamp_min(1e-5) / 15).to(dtype)
                zp = (-low / scale.float()).round().clamp(0, 15).to(torch.uint8)
                values = (blocks / scale.float().unsqueeze(-1)).round() + zp.unsqueeze(-1)
            else:
                scale = torch.maximum(blocks.amax(-1) / 7, -blocks.amin(-1) / 8).clamp_min(1e-5).to(dtype)
                zp = torch.full_like(scale, 8, dtype=torch.uint8)
                values = (blocks / scale.float().unsqueeze(-1)).round() + 8
            unpacked = values.clamp(0, 15).to(torch.uint8).reshape_as(weight)
            q = (unpacked[..., ::2] | (unpacked[..., 1::2] << 4)).contiguous()
            refs[i] = ((unpacked.reshape_as(blocks).float() - zp.unsqueeze(-1)) * scale.unsqueeze(-1)).reshape_as(weight).to(dtype)
            scales[i] = scale.contiguous()
            zeros[i] = zp.contiguous() if spec.has_zp else None
        elif spec.quant_type == 'int4_w4a8_channel':
            scale = torch.maximum(weight.float().amax(-1, keepdim=True) / 7,
                                  -weight.float().amin(-1, keepdim=True) / 8).clamp_min(1e-5)
            signed = (weight / scale).round().clamp(-8, 7).to(torch.int8)
            unsigned = signed.to(torch.uint8) & 15
            # BoltOPs channel kernel: even K is the high nibble.
            q = ((unsigned[..., ::2] << 4) | unsigned[..., 1::2]).to(torch.int8).contiguous()
            scales[i] = scale.contiguous()
            refs[i] = (signed.float() * scale).to(dtype)
        else:
            from aiter import dtypes, pertoken_quant
            if dtypes.fp8 == torch.uint8:
                raise RuntimeError("FP8 is unavailable on this device")
            q, scales[i] = pertoken_quant(weight, quant_dtype=dtypes.fp8)
        quantized.append(q)
    return dict(x=x, w1=quantized[0], w2=quantized[1], s1=scales[0], s2=scales[1],
                z1=zeros[0], z2=zeros[1], ids=ids, weights=weights, ref_w1=refs[0], ref_w2=refs[1])


def packed_zero_points(data, backend):
    packed = []
    for key in ('z1', 'z2'):
        zp = data[key]
        if zp is not None:
            if backend == 'asm':
                zp = zp[..., ::2] | (zp[..., 1::2] << 4)
            else:
                zp = zp[:, ::2, :] | (zp[:, 1::2, :] << 4)
            zp = zp.contiguous()
        packed.append(zp)
    return dict(w1_zp=packed[0], w2_zp=packed[1])


def reference(spec, data):
    if spec.quant_type == "f8_w8a8_channel":
        from aiter.moe_c_golden import run_fp8_channelwise_golden
        return run_fp8_channelwise_golden(data["x"], data["w1"], data["w2"], data["weights"],
            data["ids"], torch_dtype(spec), data["s1"], data["s2"], None, spec.experts)
    # Expert-wise Torch reference avoids a [M,topk,2I,D] weight expansion.
    out = torch.zeros_like(data["x"], dtype=torch.float32)
    for expert in range(spec.experts):
        tokens, slots = torch.where(data["ids"] == expert)
        if tokens.numel() == 0:
            continue
        fc1 = data["x"][tokens].float() @ data["ref_w1"][expert].float().T
        gate, up = fc1.chunk(2, -1)
        fc2 = (F.silu(gate) * up) @ data["ref_w2"][expert].float().T
        out.index_add_(0, tokens, fc2 * data["weights"][tokens, slots, None])
    return out.to(torch_dtype(spec))


def check(result, ref):
    if result.shape != ref.shape or not torch.isfinite(result).all() or not torch.isfinite(ref).all():
        raise RuntimeError("non-finite output/reference or wrong output shape")
    from aiter.test_common import checkAllclose
    error_ratio = float(checkAllclose(ref, result, rtol=0.01, atol=0.5, printLog=False))
    diff = (result.float() - ref.float()).abs()
    mean = float(diff.mean())
    relative = mean / max(float(ref.float().abs().mean()), 1e-12)
    metrics = dict(error_ratio=error_ratio, relative_mean_error=relative,
                   mean_abs_error=mean, max_abs_error=float(diff.max()))
    if not math.isfinite(relative) or error_ratio > 0.03 or relative >= 0.05:
        raise RuntimeError(f"accuracy failed: {metrics}")
    return metrics


def benchmark(fn, warmup, iterations, use_graph=False):
    for _ in range(warmup):
        fn()
    graph = None
    if use_graph:
        torch.cuda.synchronize()
        graph = torch.cuda.CUDAGraph()
        with torch.cuda.graph(graph):
            for _ in range(iterations):
                graph_output = fn()
        graph.replay()
        torch.cuda.synchronize()
    samples = []
    for _ in range(3):
        start, end = torch.cuda.Event(enable_timing=True), torch.cuda.Event(enable_timing=True)
        start.record()
        if graph is not None:
            graph.replay()
        else:
            for _ in range(iterations):
                fn()
        end.record(); end.synchronize()
        samples.append(start.elapsed_time(end) * 1000 / iterations)
    if not all(math.isfinite(x) and x > 0 for x in samples):
        raise RuntimeError(f"invalid timing {samples}")
    return dict(median_us=statistics.median(samples), rounds_us=samples,
                measurement='cuda_graph_gpu' if use_graph else 'eager_cuda_events')


def quant_flags(spec, backend='triton'):
    return dict(use_int8_w8a8=spec.quant_type in ('int8_w8a8_channel', 'int8_w8a8_block'),
                use_fp8_w8a8=spec.quant_type in ('f8_w8a8_channel', 'f8_w8a8_block'),
                use_int4_w4a16=spec.quant_type == 'int4_w4a16',
                use_int8_w8a16=spec.quant_type == 'int8_w8a16',
                **{('use_int8_w4a8' if backend == 'asm' else 'use_int4_w4a8'):
                   spec.quant_type in ('int4_w4a8', 'int4_w4a8_channel')},
                per_channel_quant=spec.block_shape is None and spec.quant_type != 'no_quant')


def runtime_quant(spec):
    from aiter.moe import MoeQuantType
    return {"no_quant": MoeQuantType.W16A16, "int8_w8a8_channel": MoeQuantType.W8A8,
            "f8_w8a8_channel": MoeQuantType.FP8_W8A8,
            'int8_w8a8_block': MoeQuantType.W8A8, 'f8_w8a8_block': MoeQuantType.FP8_W8A8,
            'int4_w4a16': MoeQuantType.W4A16, 'int4_w4a8': MoeQuantType.W4A8,
            'int4_w4a8_channel': MoeQuantType.W4A8, 'int8_w8a16': MoeQuantType.INT8_W8A16}[spec.quant_type]


def get_config(spec, m, backend):
    from aiter.moe import get_aiter_moe_config
    ok, cfg = get_aiter_moe_config(M=m, E=spec.experts, N1=2 * spec.inter_dim,
        N2=spec.model_dim, K=spec.model_dim, top_k=spec.topk, block_size=spec.q_size_k,
        dtype=torch_dtype(spec), quant_type=runtime_quant(spec),
        use_shuffle=spec.shuffle if backend == "asm" else 0, spec_sol_type=backend)
    if not ok or cfg.solution_type != backend:
        raise RuntimeError(f"cannot select requested {backend} config for M={m}")
    return cfg


def public_call(spec, data, cfg, inplace=False):
    from aiter.moe import aiter_moe, aiter_moe_shfl_weight
    w1, w2 = data["w1"], data["w2"]
    zeros = packed_zero_points(data, cfg.solution_type)
    if cfg.need_shuffle:
        w1, w2 = aiter_moe_shfl_weight(w1, w2, cfg)
    # Shuffle is outside timing. Only the out-of-place call is benchmarked;
    # inplace correctness gets a fresh clone on each invocation.
    def call():
        x = data["x"].clone() if inplace else data["x"]
        return aiter_moe(hidden_states=x, w1=w1, w2=w2, topk_weights=data["weights"], topk_ids=data["ids"],
            moe_config=cfg, inplace=inplace, activation=spec.activation, w1_scale=data["s1"],
            w2_scale=data["s2"], **zeros, block_shape=spec.block_shape, global_num_experts=spec.experts,
            use_weight_shuffle=bool(cfg.need_shuffle), output_dtype=torch_dtype(spec))
    return call
