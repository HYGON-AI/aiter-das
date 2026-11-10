# SPDX-License-Identifier: MIT
"""FlashKDA 的 K2 Python 层：参数校验、workspace 视图与 native 绑定。

只保留 `module_flash_kda_hcu` 里真实注册的入口（见
`csrc/pybind/flash_kda_hcu_pybind.cu`）：
`kda_k2_forward` / `kda_k2_varlen_forward` / `kda_segment_affine_forward` /
`kda_segment_replay_forward` / `kda_segment_scan_forward`。
K1 在 `aiter/ops/opus/flash_kda_k1.py`；路由在 `flash_kda_route.py`。
"""

import torch

from ...jit.core import compile_ops
from ..flash_kda_state import resolve_state_dtype
from .flash_kda_workspace import FlashKdaWorkspace

C16 = 16
K = 128
V = 128


@compile_ops("module_flash_kda_hcu", fc_name="kda_k2_forward")
def _kda_k2_forward(
    ws_kdqd: torch.Tensor,
    ws_krgt: torch.Tensor,
    ws_inv: torch.Tensor,
    ws_mqk: torch.Tensor,
    v: torch.Tensor,
    beta_sigmoid: torch.Tensor,
    out: torch.Tensor,
    initial_state: torch.Tensor,
    final_state: torch.Tensor,
    state_v_first: bool,
) -> None: ...


@compile_ops("module_flash_kda_hcu", fc_name="kda_k2_varlen_forward")
def _kda_k2_varlen_forward(
    ws_kdqd: torch.Tensor,
    ws_krgt: torch.Tensor,
    ws_inv: torch.Tensor,
    ws_mqk: torch.Tensor,
    v: torch.Tensor,
    beta_sigmoid: torch.Tensor,
    out: torch.Tensor,
    initial_state: torch.Tensor,
    final_state: torch.Tensor,
    sequence_info: torch.Tensor,
    state_v_first: bool,
) -> None: ...


@compile_ops("module_flash_kda_hcu", fc_name="kda_segment_affine_forward")
def _kda_segment_affine_forward(
    ws_kdqd: torch.Tensor,
    ws_krgt: torch.Tensor,
    ws_inv: torch.Tensor,
    v: torch.Tensor,
    beta_sigmoid: torch.Tensor,
    segment_update: torch.Tensor,
    segment_transition: torch.Tensor,
    segment_count: int,
    chunks_per_segment: int,
) -> None: ...


@compile_ops("module_flash_kda_hcu", fc_name="kda_segment_replay_forward")
def _kda_segment_replay_forward(
    ws_kdqd: torch.Tensor,
    ws_krgt: torch.Tensor,
    ws_inv: torch.Tensor,
    ws_mqk: torch.Tensor,
    v: torch.Tensor,
    beta_sigmoid: torch.Tensor,
    out: torch.Tensor,
    final_state: torch.Tensor,
    segment_initial_states: torch.Tensor,
    segment_count: int,
    chunks_per_segment: int,
    state_v_first: bool,
) -> None: ...


@compile_ops("module_flash_kda_hcu", fc_name="kda_segment_scan_forward")
def _kda_segment_scan_forward(
    segment_transition: torch.Tensor,
    segment_update: torch.Tensor,
    segment_initial_states: torch.Tensor,
    initial_state: torch.Tensor,
    segment_count: int,
    state_v_first: bool,
) -> None: ...


def _check_workspace(workspace: FlashKdaWorkspace) -> None:
    """校验 workspace 五个字段的形状、dtype、连续性与同设备（不读 GPU 内容）。"""
    if not isinstance(workspace, FlashKdaWorkspace):
        raise TypeError("workspace must be a FlashKdaWorkspace")
    p = workspace.kdqd.shape[0]
    expected = {
        "kdqd": ((p, 2, 8, 16, 16), torch.bfloat16),
        "krgt": ((p, 9, 16, 16), torch.bfloat16),
        "inv": ((p, 1, 1, 16, 16), torch.bfloat16),
        "mqk": ((p, 1, 1, 16, 16), torch.bfloat16),
        "beta_sigmoid": ((p, 16), torch.float32),
    }
    tensors = {}
    for name, (shape, dtype) in expected.items():
        tensor = getattr(workspace, name)
        if not isinstance(tensor, torch.Tensor):
            raise TypeError(f"workspace {name} must be a tensor")
        if tuple(tensor.shape) != shape or tensor.dtype is not dtype:
            raise ValueError(f"C16 workspace is unsupported: {name}")
        if not tensor.is_cuda or not tensor.is_contiguous():
            raise ValueError(f"C16 workspace {name} must be contiguous CUDA")
        tensors[name] = tensor
    device = workspace.kdqd.device
    if any(tensor.device != device for tensor in tensors.values()):
        raise ValueError("C16 workspace tensors must use the same device")


def _state_buffers(B: int, H: int, dtype: torch.dtype, device: torch.device,
                   initial_state: torch.Tensor | None,
                   output_final_state: bool) -> tuple[torch.Tensor, torch.Tensor]:
    """按入口契约生成 (initial_arg, final_state) 两个 native 参数。"""
    empty = torch.empty((0,), device=device, dtype=dtype)
    initial_arg = empty if initial_state is None else initial_state
    final_state = torch.empty((B, H, K, V), device=device, dtype=dtype) \
        if output_final_state else empty
    return initial_arg, final_state


def flash_kda_k2_forward(
    workspace: FlashKdaWorkspace,
    v: torch.Tensor,
    beta: torch.Tensor,
    *,
    initial_state: torch.Tensor | None = None,
    output_final_state: bool = False,
    out: torch.Tensor | None = None,
    state_dtype: torch.dtype | None = None,
    state_v_first: bool = False,
) -> tuple[torch.Tensor, torch.Tensor | None]:
    """定长 K2；外部 state 支持 FP32/BF16，初态/终态同 dtype（内部递推恒 FP32）。

    state_v_first 选择外部 state 布局（False = [B,H,K,V]，True = [B,H,V,K]）；
    初态与终态必须使用同一布局，K=V=128 时形状相同。
    """
    _check_workspace(workspace)
    if v.ndim != 4 or v.dtype is not torch.bfloat16 or not v.is_cuda or not v.is_contiguous():
        raise ValueError("C16 K2 v must be contiguous CUDA BF16 [B,T,H,128]")
    if beta.ndim != 3 or beta.dtype not in (torch.float32, torch.bfloat16) or not beta.is_cuda or not beta.is_contiguous():
        raise ValueError("C16 K2 beta must be contiguous CUDA FP32/BF16 [B,T,H]")
    B, T, H, V = v.shape
    if V != 128 or tuple(beta.shape) != (B, T, H):
        raise ValueError("C16 K2 requires v=[B,T,H,128] and beta=[B,T,H]")
    expected_p = B * H * ((T + 15) // 16)
    if workspace.kdqd.shape[0] != expected_p:
        raise ValueError("C16 workspace P does not match v shape")
    state_dtype = resolve_state_dtype(initial_state, state_dtype)
    if out is None:
        out = torch.empty_like(v)
    if (tuple(out.shape) != tuple(v.shape) or out.dtype is not torch.bfloat16
            or not out.is_cuda or not out.is_contiguous() or out.device != v.device):
        raise ValueError("out must be contiguous CUDA BF16 with v shape")
    if initial_state is not None:
        if (initial_state.dtype is not state_dtype or initial_state.ndim != 4
                or tuple(initial_state.shape) != (B, H, 128, 128)
                or not initial_state.is_cuda or not initial_state.is_contiguous()
                or initial_state.device != v.device):
            raise ValueError(
                f"initial_state must be contiguous CUDA {state_dtype} [B,H,128,128]"
            )
    initial_arg, final_state = _state_buffers(
        B, H, state_dtype, v.device, initial_state, output_final_state)
    _kda_k2_forward(
        workspace.kdqd, workspace.krgt, workspace.inv, workspace.mqk,
        v, workspace.beta_sigmoid, out, initial_arg, final_state, state_v_first,
    )
    return out, final_state if output_final_state else None


def flash_kda_k2_varlen_forward(
    workspace: FlashKdaWorkspace,
    v: torch.Tensor,
    beta: torch.Tensor,
    *,
    sequence_info: torch.Tensor,
    initial_state: torch.Tensor | None = None,
    output_final_state: bool = False,
    out: torch.Tensor | None = None,
    state_dtype: torch.dtype | None = None,
    state_v_first: bool = False,
) -> tuple[torch.Tensor, torch.Tensor | None]:
    """packed 变长 K2：一次 launch 处理 N 条序列（含空序列）。

    契约（K1 生产者与 K2 消费端共用）：

    * ``v`` / ``beta`` / ``out`` 是 **物理 B=1** 的 packed 张量：
      ``[1, T_total, H, 128]`` / ``[1, T_total, H]`` / ``[1, T_total, H, 128]``，
      允许 ``T_total == 0``。
    * ``sequence_info`` 是 INT64 CUDA contiguous ``[N,3]`` 的 AoS 三列：
      ``[:,0] = sequence_token_offset``（本序列全局 packed token 起点）、
      ``[:,1] = L``（本序列长度，**允许 0**）、
      ``[:,2] = chunk0``（本序列在每个 head 的 chunk 槽起点，chunk 单位）。
      空序列不占 chunk 槽，因此相邻序列的 ``chunk0`` 可以相同。
    * workspace 外层是 head-major：``p(head,s,c) = head*Qcap +
      sequence_info[s,2] + c``，``Qcap = workspace.kdqd.shape[0] / H`` 是每个 head
      已分配的 chunk 槽容量。**不能**用实际使用 chunk 数当 head stride。
    * 状态为 ``[N,H,128,128]``，FP32 或 BF16（``state_dtype`` 解析规则与定长一致：
      不指定且无初态 → FP32；有初态则跟初态 dtype；显式与推断冲突报错）。
      初态/终态必须同 dtype；每条序列独立零初始化或读自己的初态；空序列请求
      终态时写回自己的初态（无初态则零）。

    本函数**不做 D2H 回读**：metadata 内容有效性是生产者的前置契约。
    """
    _check_workspace(workspace)
    resolved_state_dtype = resolve_state_dtype(initial_state, state_dtype)
    if v.ndim != 4 or v.dtype is not torch.bfloat16 or not v.is_cuda or not v.is_contiguous():
        raise ValueError("C16 K2 varlen v must be contiguous CUDA BF16 [1,T_total,H,128]")
    if beta.ndim != 3 or beta.dtype not in (torch.float32, torch.bfloat16) or not beta.is_cuda or not beta.is_contiguous():
        raise ValueError("C16 K2 varlen beta must be contiguous CUDA FP32/BF16 [1,T_total,H]")
    B, T, H, V = v.shape
    if B != 1:
        raise ValueError("C16 K2 varlen requires physical batch B=1 (packed input)")
    if H <= 0 or V != 128 or tuple(beta.shape) != (B, T, H):
        raise ValueError("C16 K2 varlen requires v=[1,T_total,H,128] and beta=[1,T_total,H]")
    if (sequence_info.dtype is not torch.int64 or sequence_info.ndim != 2
            or int(sequence_info.size(1)) != 3 or int(sequence_info.size(0)) < 1
            or not sequence_info.is_cuda or not sequence_info.is_contiguous()
            or sequence_info.device != v.device):
        raise ValueError(
            "C16 K2 varlen sequence_info must be contiguous CUDA INT64 [N,3] with N>=1"
        )
    n_seqs = int(sequence_info.size(0))
    p = int(workspace.kdqd.shape[0])
    if p % H:
        raise ValueError("C16 K2 varlen requires workspace P divisible by H")
    if p // H < 1:
        raise ValueError("C16 K2 varlen requires at least one workspace chunk slot")
    if out is None:
        out = torch.empty_like(v)
    if (tuple(out.shape) != tuple(v.shape) or out.dtype is not torch.bfloat16
            or not out.is_cuda or not out.is_contiguous() or out.device != v.device):
        raise ValueError("out must be contiguous CUDA BF16 with v shape")
    # 初态形状用 N（不是 B）；定长/变长同一套 dtype 规则。
    if initial_state is not None:
        if (initial_state.dtype is not resolved_state_dtype or initial_state.ndim != 4
                or tuple(initial_state.shape) != (n_seqs, H, 128, 128)
                or not initial_state.is_cuda or not initial_state.is_contiguous()
                or initial_state.device != v.device):
            raise ValueError(
                f"initial_state must be contiguous CUDA {resolved_state_dtype} "
                "[N,H,128,128]"
            )
    # 空张量也要带 state_dtype：C++ 侧按它的 dtype 分派 StateBf16 实例。
    initial_arg, final_state = _state_buffers(
        n_seqs, H, resolved_state_dtype, v.device, initial_state, output_final_state)
    _kda_k2_varlen_forward(
        workspace.kdqd, workspace.krgt, workspace.inv, workspace.mqk,
        v, workspace.beta_sigmoid, out, initial_arg, final_state, sequence_info,
        state_v_first,
    )
    return out, final_state if output_final_state else None


def flash_kda_k2_segmented_forward(
    workspace: FlashKdaWorkspace,
    v: torch.Tensor,
    beta: torch.Tensor,
    *,
    chunks_per_segment: int,
    initial_state: torch.Tensor | None = None,
    output_final_state: bool = False,
    out: torch.Tensor | None = None,
    state_dtype: torch.dtype | None = None,
    state_v_first: bool = False,
) -> tuple[torch.Tensor, torch.Tensor | None]:
    """分段 K2：affine pass → 段间 scan → replay（定长 state 支持 FP32/BF16）。

    state_v_first 只改外部初/终态布局；segment_update /
    segment_initial_states 仍按自然 [K,V] 存储，不随外部布局转置。
    """
    _check_workspace(workspace)
    if v.ndim != 4 or v.dtype is not torch.bfloat16 or not v.is_cuda or not v.is_contiguous():
        raise ValueError("C16 segmented K2 v must be contiguous CUDA BF16 [B,T,H,128]")
    if beta.ndim != 3 or beta.dtype not in (torch.float32, torch.bfloat16) or not beta.is_cuda or not beta.is_contiguous():
        raise ValueError("C16 segmented K2 beta must be contiguous CUDA FP32/BF16 [B,T,H]")
    B, T, H, V = v.shape
    if V != 128 or tuple(beta.shape) != (B, T, H):
        raise ValueError("C16 segmented K2 requires v=[B,T,H,128]")
    if chunks_per_segment <= 0:
        raise ValueError("chunks_per_segment must be positive")
    expected_p = B * H * ((T + 15) // 16)
    if workspace.kdqd.shape[0] != expected_p:
        raise ValueError("C16 workspace P does not match v shape")
    state_dtype = resolve_state_dtype(initial_state, state_dtype)
    if out is None:
        out = torch.empty_like(v)
    if (tuple(out.shape) != tuple(v.shape) or out.dtype is not torch.bfloat16
            or not out.is_cuda or not out.is_contiguous() or out.device != v.device):
        raise ValueError("out must be contiguous CUDA BF16 with v shape")
    if initial_state is not None:
        if (initial_state.dtype is not state_dtype or initial_state.ndim != 4
                or tuple(initial_state.shape) != (B, H, 128, 128)
                or not initial_state.is_cuda or not initial_state.is_contiguous()
                or initial_state.device != v.device):
            raise ValueError(
                f"initial_state must be contiguous CUDA {state_dtype} [B,H,128,128]"
            )
    initial_arg, final_state = _state_buffers(
        B, H, state_dtype, v.device, initial_state, output_final_state)
    chunks = (T + 15) // 16
    segments = (chunks + chunks_per_segment - 1) // chunks_per_segment
    segment_update = torch.empty((segments, B, H, 128, 128), device=v.device, dtype=torch.float32)
    segment_transition = torch.empty((segments, B, H, 128, 128), device=v.device, dtype=torch.bfloat16)
    beta_sigmoid_arg = workspace.beta_sigmoid
    _kda_segment_affine_forward(
        workspace.kdqd, workspace.krgt, workspace.inv, v, beta_sigmoid_arg,
        segment_update, segment_transition, segments, chunks_per_segment,
    )
    segment_initial_states = torch.empty_like(segment_update)
    _kda_segment_scan_forward(segment_transition, segment_update,
                              segment_initial_states, initial_arg, segments,
                              state_v_first)
    _kda_segment_replay_forward(
        workspace.kdqd, workspace.krgt, workspace.inv, workspace.mqk,
        v, beta_sigmoid_arg, out, final_state, segment_initial_states, segments,
        chunks_per_segment, state_v_first,
    )
    return out, final_state if output_final_state else None
