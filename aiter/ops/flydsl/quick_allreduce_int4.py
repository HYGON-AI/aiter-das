# SPDX-License-Identifier: MIT
# Copyright (C) 2026, Advanced Micro Devices, Inc. All rights reserved.
# Adapted from upstream AITER 89a47b84 for HCU, with collective initialization
# and an existing HIP non-quantized path for small payloads.
"""Single-node BF16 INT4 AllReduce for HCU gfx936/gfx938."""
from __future__ import annotations

import ctypes
import os
import threading

import torch
import torch.distributed as dist
import flydsl.compiler as flyc
from flydsl.expr.typing import Int32, Int64, Stream

from .kernels.quick_allreduce_int4 import (
    DEFAULT_GRID_CAP, SUPER_TILES, SUPPORTED_WORLDS, TILE_BYTES, WORLD,
    clamp_grid_cap, make_quick_allreduce_int4_kernel,
)
from .quick_allreduce_int4_ipc import UncachedIpcHeap as Heap

_COMPILE_LOCK = threading.RLock()
SMALL_PAYLOAD_BYTES = TILE_BYTES


def _stage(group, name, operation):
    """Reach one decision before any rank advances to the next IPC stage."""
    value, error = None, None
    try:
        value = operation()
    except Exception as exc:
        error = f"rank {dist.get_rank(group)}: {type(exc).__name__}: {exc}"
    errors = [None] * dist.get_world_size(group)
    dist.all_gather_object(errors, error, group=group)
    if any(errors):
        raise RuntimeError(f"INT4 {name} failed collectively: " + "; ".join(e for e in errors if e))
    return value


def _cuda_index(device):
    if isinstance(device, int):
        return device
    device = torch.device(device)
    if device.type != "cuda":
        raise ValueError("QuickAllReduceInt4 requires a CUDA/HIP device")
    return torch.cuda.current_device() if device.index is None else device.index


def _torch_stream(stream, device):
    if stream is None:
        return torch.cuda.current_stream(device)
    raw = stream.value if isinstance(stream, Stream) else stream
    if raw is None:
        return torch.cuda.default_stream(device)
    if isinstance(raw, int):
        return torch.cuda.ExternalStream(raw, device=device)
    if not isinstance(raw, torch.cuda.Stream) or raw.device != device:
        raise ValueError("stream must belong to the communicator's device")
    return raw


class _StEngine:
    def __init__(self, spec, group, rank, world_size):
        self.spec, self.launch = spec, spec['launch']
        for name in ('super_tile', 'grid', 'lds_bytes', 'tile_bytes',
                     'tile_fp16', 'rank_tile_bytes', 'wire_tile_bytes'):
            setattr(self, name, spec[name])
        self.buf_bytes = spec['flags_bytes'] + spec['data_bytes']
        self._buf_ptr = self._meta_ptr = 0
        self._peer_bases, self.compiled = [], None
        try:
            def allocate():
                self._buf_ptr = Heap.alloc_uncached(self.buf_bytes)
            _stage(group, 'inbox allocation', allocate)
            handle = _stage(group, 'handle export', lambda: Heap.get_mem_handle_bytes(self._buf_ptr))
            handles = [None] * world_size
            dist.all_gather_object(handles, handle, group=group)
            peers = []
            def attach():
                for r in range(world_size):
                    ptr = self._buf_ptr if r == rank else Heap.open_mem_handle(handles[r])
                    if r != rank:
                        self._peer_bases.append(ptr)
                    peers.append(ptr)
            _stage(group, 'peer attach', attach)
            def metadata():
                self._meta_ptr = Heap.alloc_uncached(world_size * 8 + self.grid * 4)
                Heap.copy_host_to_device(self._meta_ptr, (ctypes.c_int64 * world_size)(*peers), world_size * 8)
                Heap.copy_host_to_device(self._meta_ptr + world_size * 8,
                                        (ctypes.c_int32 * self.grid)(*([1] * self.grid)), self.grid * 4)
            _stage(group, 'metadata allocation', metadata)
        except Exception:
            self.close()
            raise

    def close(self):
        for ptr in self._peer_bases:
            Heap.close_mem_handle(ptr)
        self._peer_bases.clear()
        for name in ('_meta_ptr', '_buf_ptr'):
            ptr = getattr(self, name)
            if ptr:
                Heap.free_device_mem(ptr)
                setattr(self, name, 0)


class _SmallFpEngine:
    """Reuse native QR static IPC buffers and FP codec, preserving BF16."""
    def __init__(self, group, rank, world_size):
        from aiter.ops import quick_all_reduce as qr
        from aiter.ops.custom_all_reduce import meta_size
        self.qr, self.ptr = qr, 0
        try:
            # The existing develop=True tensor adapter obtains its shared
            # pybind type from custom AR, even when dispatching a QR kernel.
            _stage(group, 'small FP tensor ABI preload', meta_size)
            def allocate():
                self.ptr = qr.init_custom_qr(rank, world_size, SMALL_PAYLOAD_BYTES)
            _stage(group, 'small FP allocation', allocate)
            handle = _stage(group, 'small FP handle export', lambda: qr.qr_get_handle(self.ptr))
            handles = [None] * world_size
            dist.all_gather_object(handles, handle, group=group)
            _stage(group, 'small FP peer attach', lambda: qr.qr_open_handles(self.ptr, handles))
        except Exception:
            self.close()
            raise

    def run(self, inp, out):
        self.qr.qr_all_reduce(self.ptr, inp, out, 0, False)

    def close(self):
        if self.ptr:
            self.qr.qr_destroy(self.ptr)
            self.ptr = 0


class QuickAllReduceInt4:
    """BF16 out-of-place AllReduce with INT4 communication on gfx936/gfx938.

    Construct/compile/close collectively on a same-node CPU process group.
    All ranks must call with identical payload sizes and ordered stream use.
    Warm with compile() before Graph capture. Replays using one communicator
    must not overlap; destroy graphs before close().

    small_payload_policy='fp' (default) avoids INT4 quantization at <=32 KiB
    using existing HIP QR without BF16-to-FP16 casting. 'int4' explicitly opts
    into lossy INT4 even for tiny payloads. INT4 does not guarantee a fixed
    relative-error bound for every possible input distribution.
    """
    def __init__(self, *, group, device, rank, world_size=WORLD, super_tile=8,
                 grid_cap=None, small_payload_policy='fp'):
        self._by_st, self._small_fp = {}, None
        self._closed, self._ready, self._has_launched = False, False, False
        self.group = group
        if dist.get_backend(group) == dist.Backend.NCCL:
            raise ValueError('INT4 requires a CPU process group for IPC metadata')
        def validate():
            if world_size not in SUPPORTED_WORLDS or super_tile not in SUPER_TILES:
                raise ValueError('INT4 supports TP2/4/8 and ST1/8')
            if dist.get_world_size(group) != world_size or dist.get_rank(group) != rank:
                raise ValueError('rank/world_size do not match the process group')
            if small_payload_policy not in ('fp', 'int4'):
                raise ValueError("small_payload_policy must be 'fp' or 'int4'")
            if os.environ.get('AITER_AR_TRANSPORT', 'ipc').lower() == 'fabric':
                raise ValueError('QuickAllReduceInt4 uses node-local IPC, not Fabric')
            self._device_index = _cuda_index(device)
            self.device = torch.device('cuda', self._device_index)
            props = torch.cuda.get_device_properties(self.device)
            self.arch = props.gcnArchName.split(':')[0]
            target = os.environ.get('FLYDSL_GPU_ARCH', self.arch).split(':')[0]
            if target != self.arch:
                raise ValueError(f'FLYDSL_GPU_ARCH={target} differs from device {self.arch}')
            cap = DEFAULT_GRID_CAP if grid_cap is None else int(grid_cap)
            grid = clamp_grid_cap(cap, arch=self.arch, world_size=world_size,
                                  super_tile=super_tile, cu_count=props.multi_processor_count)
            return (world_size, super_tile, cap, small_payload_policy, self.arch), grid
        config, grid = _stage(group, 'configuration', validate)
        configs = [None] * world_size
        dist.all_gather_object(configs, config, group=group)
        if any(c != config for c in configs):
            raise ValueError('INT4 configuration must agree on all ranks')
        from aiter.dist.parallel_state import in_the_same_node_as
        from aiter.dist.device_communicators.topology import is_fully_connected
        if not all(in_the_same_node_as(group, source_rank=0)):
            raise RuntimeError('INT4 HIP IPC requires a single-node process group')
        if not is_fully_connected(group, self.device):
            raise RuntimeError('INT4 requires distinct, fully connected HIP devices')
        self.rank, self.world_size, self.super_tile = rank, world_size, super_tile
        self.small_payload_policy = small_payload_policy
        self.small_payload_bytes = SMALL_PAYLOAD_BYTES if small_payload_policy == 'fp' else 0
        shared = torch.tensor(grid, dtype=torch.int64)
        dist.all_reduce(shared, op=dist.ReduceOp.MIN, group=group)
        grid = int(shared.item())
        try:
            with torch.cuda.device(self.device):
                for st in ([1, 8] if super_tile == 8 else [1]):
                    spec = make_quick_allreduce_int4_kernel(world_size=world_size, super_tile=st, grid=grid)
                    self._by_st[st] = _StEngine(spec, group, rank, world_size)
                if self.small_payload_bytes:
                    self._small_fp = _SmallFpEngine(group, rank, world_size)
            primary = self._by_st[super_tile]
            for name in ('buf_bytes', 'lds_bytes', 'tile_bytes', 'tile_fp16', 'rank_tile_bytes', 'wire_tile_bytes'):
                setattr(self, name, getattr(primary, name))
            self._ready = True
        except Exception:
            self.close(collective=False)
            raise

    def _check_payload(self, inp, out):
        if self._closed:
            raise RuntimeError('QuickAllReduceInt4 is closed')
        if not isinstance(inp, torch.Tensor) or not isinstance(out, torch.Tensor):
            raise TypeError('input and output must be tensors')
        for t in (inp, out):
            if t.dtype != torch.bfloat16 or t.device != self.device or not t.is_contiguous():
                raise ValueError('input/output must be contiguous BF16 on the communicator device')
            if t.data_ptr() % 16:
                raise ValueError('input/output pointers must be 16-byte aligned')
        nbytes = inp.numel() * 2
        if nbytes > 0xFFFFFFFF or nbytes % 16 or out.numel() != inp.numel():
            raise ValueError('equal input/output sizes, a 16-byte multiple and <4 GiB, are required')
        if max(inp.data_ptr(), out.data_ptr()) < min(inp.data_ptr()+nbytes, out.data_ptr()+nbytes):
            raise ValueError('input and output must not overlap')
        return nbytes

    def _args(self, eng, inp, out, stream, nbytes):
        tiles = max(1, (nbytes + TILE_BYTES - 1) // TILE_BYTES)
        return (Int32(self.rank), Int64(nbytes), Int32(tiles), Int64(inp.data_ptr()),
                Int64(out.data_ptr()), Int64(eng._meta_ptr),
                Int64(eng._meta_ptr + self.world_size * 8), Int32(min(tiles, eng.grid)), Stream(stream))

    def _ensure_compiled(self, inp, out, stream, nbytes):
        if all(e.compiled is not None for e in self._by_st.values()):
            return
        if torch.cuda.is_current_stream_capturing():
            raise RuntimeError('Call compile() on all ranks before Graph capture')
        def preload():
            with _COMPILE_LOCK:
                old = os.environ.get('COMPILE_ONLY')
                os.environ['COMPILE_ONLY'] = '1'
                try:
                    for eng in self._by_st.values():
                        eng.compiled = flyc.compile(eng.launch, *self._args(eng, inp, out, stream, nbytes))
                        if eng.compiled is None:
                            raise RuntimeError('FlyDSL compile-only did not return a compiled function')
                finally:
                    if old is None:
                        os.environ.pop('COMPILE_ONLY', None)
                    else:
                        os.environ['COMPILE_ONLY'] = old
        try:
            _stage(self.group, 'kernel preload', preload)
        except Exception:
            # Keep readiness identical across ranks so a collective retry
            # cannot leave successful ranks skipping the preload agreement.
            for eng in self._by_st.values():
                eng.compiled = None
            raise

    def compile(self, inp, out, stream=None):
        """Collectively compile/warm every ST binary; out is overwritten."""
        nbytes = self._check_payload(inp, out)
        with torch.cuda.device(self.device):
            stream = _torch_stream(stream, self.device)
            self._ensure_compiled(inp, out, stream, nbytes)
            if nbytes:
                self._has_launched = True
                for eng in self._by_st.values():
                    eng.compiled(*self._args(eng, inp, out, stream, nbytes))
        self.allreduce(inp, out, stream)

    def allreduce(self, inp, out, stream=None):
        nbytes = self._check_payload(inp, out)
        if not nbytes:
            return
        with torch.cuda.device(self.device):
            stream = _torch_stream(stream, self.device)
            self._has_launched = True
            if nbytes <= self.small_payload_bytes:
                with torch.cuda.stream(stream):
                    self._small_fp.run(inp, out)
                return
            self._ensure_compiled(inp, out, stream, nbytes)
            tiles = (nbytes + TILE_BYTES - 1) // TILE_BYTES
            st = 1 if tiles <= self._by_st[1].grid else self.super_tile
            eng = self._by_st[st]
            eng.compiled(*self._args(eng, inp, out, stream, nbytes))

    def close(self, *, collective=True):
        if self._closed:
            return
        if hasattr(self, 'device'):
            with torch.cuda.device(self.device):
                if self._has_launched:
                    torch.cuda.synchronize(self.device)
                if collective and self._ready:
                    dist.barrier(group=self.group)
                for eng in self._by_st.values():
                    eng.close()
                self._by_st.clear()
                if self._small_fp is not None:
                    self._small_fp.close()
                    self._small_fp = None
        self._closed = True

    def __enter__(self):
        return self

    def __exit__(self, *_):
        self.close()

    def __del__(self):
        try:
            self.close(collective=False)
        except Exception:
            pass
