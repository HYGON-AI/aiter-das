// SPDX-License-Identifier: Apache-2.0
// Copyright (C) Advanced Micro Devices, Inc. All rights reserved.
// Copyright (C) 2026 Hygon Information Technology Co., Ltd.
// LL/LL128 packet layouts adapted from AITER 06e3bf795e05.
// Included inside namespace aiter, after the shared CAR conversion helpers.
#pragma once

constexpr int kHcuLLBlocks = 16;
constexpr size_t kHcuLLCap = 64 * 1024;
constexpr size_t kHcuLLSlot = kHcuLLCap / 8;

struct alignas(16) HcuLLLine { uint64_t data, epoch; };
static_assert(sizeof(HcuLLLine) == 16);

inline size_t hcu_ll_ack_bytes(int ranks) { return 2 * kHcuLLBlocks * ranks * sizeof(uint64_t); }
inline size_t hcu_ll_bytes(int ranks) { return 2 * ranks * kHcuLLSlot * sizeof(HcuLLLine); }
inline size_t hcu_ll128_slot(int ranks) {
    const size_t cap = ranks == 2 ? 896 * 1024 : 64 * 1024;
    return ((cap + 239) / 240) * 256;
}
inline size_t hcu_ll_scratch_bytes(int ranks) {
    return hcu_ll_ack_bytes(ranks) + hcu_ll_bytes(ranks) + 2 * ranks * hcu_ll128_slot(ranks);
}

DINLINE uint64_t hcu_ll_epoch(uint64_t* epochs, uint64_t& shared_epoch) {
    if(threadIdx.x == 0) {
        shared_epoch = epochs[blockIdx.x] + 1;
        // Never reuse the zero sentinel, even at an unreachable lifetime wrap.
        if(shared_epoch == 0) __builtin_trap();
    }
    __syncthreads();
    return shared_epoch;
}

template<int ngpus, int algorithm>
DINLINE void hcu_ll_finish(const RankSignals& sg, size_t scratch_offset,
                          int rank, uint64_t flag, uint64_t* epochs) {
    // Acknowledge consumption before the next collective can reuse any bank.
    // Every launch uses the same grid, including inactive blocks. This also
    // closes transitions between shapes, graphs, LL and traditional CAR.
    __syncthreads();
    if(threadIdx.x < ngpus) {
        const int peer = threadIdx.x;
        auto* remote = reinterpret_cast<uint64_t*>(reinterpret_cast<char*>(sg.signals[peer]) + scratch_offset);
        auto* local = reinterpret_cast<uint64_t*>(reinterpret_cast<char*>(sg.signals[rank]) + scratch_offset);
        const int offset = (algorithm * kHcuLLBlocks + blockIdx.x) * ngpus;
        __scoped_atomic_store_n(remote + offset + rank, flag, __ATOMIC_RELEASE, __MEMORY_SCOPE_SYSTEM);
        while(__scoped_atomic_load_n(local + offset + peer, __ATOMIC_ACQUIRE, __MEMORY_SCOPE_SYSTEM) < flag) {}
    }
    __syncthreads();
    if(threadIdx.x == 0) epochs[blockIdx.x] = flag;
}

template<typename T, int ngpus>
__global__ void __launch_bounds__(256) ar_ll_hcu(
    RankSignals sg, size_t scratch_offset, uint64_t* epochs,
    const T* input, T* output, int rank, int numel) {
    static_assert(sizeof(T) == 2);
    constexpr int LP = 8 / sizeof(T);
    using P = opus::vector_t<T, LP>;
    using A = opus::vector_t<float, LP>;
    __shared__ uint64_t shared_epoch;
    const uint64_t flag = hcu_ll_epoch(epochs, shared_epoch);
    const size_t bank = (flag & 1) * ngpus * kHcuLLSlot;
    constexpr size_t ack_bytes = 2 * kHcuLLBlocks * ngpus * sizeof(uint64_t);
    HcuLLLine* peers[ngpus];
    for(int r=0;r<ngpus;r++)
        peers[r] = reinterpret_cast<HcuLLLine*>(reinterpret_cast<char*>(sg.signals[r]) + scratch_offset + ack_bytes) + bank;
    const int tid = blockIdx.x * blockDim.x + threadIdx.x;
    const int stride = gridDim.x * blockDim.x;
    const int packets = numel / LP;
    for(int pk=tid;pk<packets;pk+=stride) {
        const uint64_t data = reinterpret_cast<const uint64_t*>(input)[pk];
        for(int r=1;r<ngpus;r++) {
            auto* line = peers[(rank+r)%ngpus] + rank*kHcuLLSlot + pk;
            // Separate release of the flag avoids any 16B atomicity assumption.
            __builtin_nontemporal_store(data, &line->data);
            __scoped_atomic_store_n(&line->epoch, flag, __ATOMIC_RELEASE, __MEMORY_SCOPE_SYSTEM);
        }
    }
    for(int pk=tid;pk<packets;pk+=stride) {
        P own = reinterpret_cast<const P*>(input)[pk];
        A acc;
        // Match ordinary one-stage's rank order on every device. Rotating the
        // first contributor with rank changes cancellation and rounding ties.
        for(int r=0;r<ngpus;r++) {
            P value = own;
            if(r != rank) {
                auto* line = peers[rank] + r*kHcuLLSlot + pk;
                while(__scoped_atomic_load_n(&line->epoch, __ATOMIC_ACQUIRE, __MEMORY_SCOPE_SYSTEM) != flag) {}
                const uint64_t data = __builtin_nontemporal_load(&line->data);
                value = __builtin_bit_cast(P, data);
            }
            for(int j=0;j<LP;j++) {
                if(r == 0) acc[j] = upcast_s(value[j]);
                else acc[j] += upcast_s(value[j]);
            }
        }
        P out;
        for(int j=0;j<LP;j++) out[j] = downcast_s<T>(acc[j]);
        reinterpret_cast<P*>(output)[pk] = out;
    }
    hcu_ll_finish<ngpus,0>(sg,scratch_offset,rank,flag,epochs);
}

using HcuLLVector = unsigned int __attribute__((vector_size(16)));
template<typename P>
DINLINE void hcu_ll128_store(P data, uint32_t* dst) {
    __builtin_nontemporal_store(__builtin_bit_cast(HcuLLVector,data), reinterpret_cast<HcuLLVector*>(dst));
}
template<typename P>
DINLINE P hcu_ll128_load(const uint32_t* src) {
    return __builtin_bit_cast(P,__builtin_nontemporal_load(reinterpret_cast<const HcuLLVector*>(src)));
}

template<typename T>
DINLINE void hcu_ll128_input(const T* input, int group, int lane, int packs,
                            opus::vector_t<T,8> (&data)[2]) {
    using P=opus::vector_t<T,8>;
    data[0]={};data[1]={};
    int index=group*15+lane;
    if(index<packs) data[0]=reinterpret_cast<const P*>(input)[index];
    if(lane<7 && index+8<packs) data[1]=reinterpret_cast<const P*>(input)[index+8];
    if(lane==7) {
        for(int j=0;j<4;j++) { data[1][j]=data[0][j+4];data[0][j+4]={}; }
    }
}

template<typename T, int ngpus, int block_size>
__global__ void __launch_bounds__(block_size) ar_ll128_hcu(
    RankSignals sg, size_t scratch_offset, size_t slot_bytes, uint64_t* epochs,
    const T* input, T* output, int rank, int numel) {
    static_assert(sizeof(T)==2);
    using P=opus::vector_t<T,8>;
    using A=opus::vector_t<float,8>;
    constexpr int groups_per_block=block_size/8;
    constexpr size_t prefix=2*kHcuLLBlocks*ngpus*sizeof(uint64_t)+2*ngpus*kHcuLLSlot*sizeof(HcuLLLine);
    const int lane=threadIdx.x%8;
    const int first=blockIdx.x*groups_per_block+threadIdx.x/8;
    const int stride=gridDim.x*groups_per_block;
    const int packs=numel/8, groups=(packs+14)/15;
    __shared__ uint64_t shared_epoch;
    const uint64_t flag=hcu_ll_epoch(epochs,shared_epoch);
    char* peers[ngpus];
    for(int r=0;r<ngpus;r++)
        peers[r]=reinterpret_cast<char*>(sg.signals[r])+scratch_offset+prefix+(flag&1)*ngpus*slot_bytes;
    // All payload stores finish at system scope before any lane publishes flags.
    // Each 256B group carries 240B data and two separately released 64-bit flags.
    for(int g=first;g<groups;g+=stride) {
        P data[2];hcu_ll128_input(input,g,lane,packs,data);
        for(int r=1;r<ngpus;r++) {
            auto* dst=reinterpret_cast<uint32_t*>(peers[(rank+r)%ngpus]+rank*slot_bytes+g*256)+lane*4;
            hcu_ll128_store(data[0],dst);hcu_ll128_store(data[1],dst+32);
        }
    }
    __threadfence_system();
    __syncthreads();
    if(lane==7) {
        for(int g=first;g<groups;g+=stride) {
            for(int r=1;r<ngpus;r++) {
                auto* dst=reinterpret_cast<uint64_t*>(peers[(rank+r)%ngpus]+rank*slot_bytes+g*256);
                __scoped_atomic_store_n(dst+15,flag,__ATOMIC_RELEASE,__MEMORY_SCOPE_SYSTEM);
                __scoped_atomic_store_n(dst+31,flag,__ATOMIC_RELEASE,__MEMORY_SCOPE_SYSTEM);
            }
        }
    }
    for(int g=first;g<groups;g+=stride) {
        P own[2];hcu_ll128_input(input,g,lane,packs,own);
        A acc[2];
        for(int r=0;r<ngpus;r++) {
            auto* src=reinterpret_cast<uint64_t*>(peers[rank]+r*slot_bytes+g*256);
            for(int half=0;half<2;half++) {
                P value = own[half];
                if(r != rank) {
                    while(__scoped_atomic_load_n(src+15+16*half,__ATOMIC_ACQUIRE,__MEMORY_SCOPE_SYSTEM)!=flag) {}
                    value=hcu_ll128_load<P>(reinterpret_cast<const uint32_t*>(src)+lane*4+half*32);
                }
                for(int j=0;j<8;j++) {
                    if(r == 0) acc[half][j] = upcast_s(value[j]);
                    else acc[half][j] += upcast_s(value[j]);
                }
            }
        }
        P result[2];
        for(int half=0;half<2;half++)
            for(int j=0;j<8;j++) result[half][j]=downcast_s<T>(acc[half][j]);
        if(lane==7) for(int j=0;j<4;j++) result[0][j+4]=result[1][j];
        int index=g*15+lane;
        if(index<packs) reinterpret_cast<P*>(output)[index]=result[0];
        if(lane<7 && index+8<packs) reinterpret_cast<P*>(output)[index+8]=result[1];
    }
    hcu_ll_finish<ngpus,1>(sg,scratch_offset,rank,flag,epochs);
}
