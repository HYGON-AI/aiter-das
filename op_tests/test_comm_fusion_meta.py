"""Shape/dtype/stride and fullgraph tracing for communication fake kernels."""
import torch
from aiter.dist import parallel_state as ps


def main():
    count = 0
    for dtype in (torch.float16, torch.bfloat16):
        for shape in ((4, 512), (2, 4, 512)):
            x = torch.empty(shape, dtype=dtype, device='meta')
            weight = torch.empty(shape[-1], dtype=dtype, device='meta')
            for emit in (False, True):
                for per_group in (False, True):
                    for transpose in ((False, True) if per_group and len(shape) == 2 else (False,)):
                        suffix = '_per_group' if per_group else ''
                        suffix += '_emit_bf16' if emit else ''
                        fn = getattr(ps, 'fused_allreduce_rmsnorm_quant' + suffix + '_')
                        kwargs = {'group_size': 128, 'transpose_scale': transpose} if per_group else {'gemma_norm': True}
                        # Independent API fixtures share the decorator code object.
                        torch._dynamo.reset()
                        compiled = torch.compile(fn, backend='eager', fullgraph=True)
                        outputs = compiled(x, x, weight, 1e-6, 'meta_only', **kwargs)
                        assert len(outputs) == (4 if emit else 3)
                        assert outputs[0].dtype == torch.float8_e4m3fn
                        assert outputs[0].shape == outputs[1].shape == shape
                        assert outputs[1].dtype == dtype
                        assert outputs[2].shape == shape[:-1] + ((4,) if per_group else (1,))
                        if transpose:
                            assert outputs[2].stride() == (1, shape[0])
                        if emit:
                            assert outputs[3].dtype == dtype and outputs[3].shape == shape
                        count += 1
        x = torch.empty((4, 520), dtype=dtype, device='meta')
        residual = torch.empty((4, 512), dtype=dtype, device='meta')
        torch._dynamo.reset()
        out, res = torch.compile(ps.fused_allreduce_rmsnorm_, backend='eager', fullgraph=True)(
            x, residual, weight, 1e-6, 'meta_only', x_pad_to_multiple=768, gemma_norm=True)
        assert out.shape == (4, 768) and res.shape == residual.shape
    print(f'COMM_FUSION_META_PASS cases={count + 2}')


if __name__ == '__main__':
    main()
