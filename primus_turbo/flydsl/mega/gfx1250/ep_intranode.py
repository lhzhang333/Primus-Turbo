###############################################################################
# SPDX-License-Identifier: Apache-2.0
#
# Copyright (c) 2026, Advanced Micro Devices, Inc. All rights reserved.
# Copyright (c) 2026 FlyDSL Project Contributors
#
# Adapted from FlyDSL (https://github.com/ROCm/FlyDSL)
# Modified by the Primus-Turbo team.
#
# This file is distributed under the Apache License 2.0 (see LICENSE-APACHE),
# not the MIT license that covers the rest of Primus-Turbo (see LICENSE).
###############################################################################

from typing import Optional

import flydsl.expr as fx
from flydsl._mlir.dialects import vector as _vector
from flydsl.compiler.ast_rewriter import ASTRewriter
from flydsl.expr import arith, const_expr, range_constexpr
from flydsl.expr.utils.arith import ArithValue

from primus_turbo.flydsl.mega.gfx1250.prims import (
    _COPY_VEC_I32,
    CPOL_DEVICE_STREAM,
    CPOL_SYSTEM_STREAM,
    WAVE,
    _readfirstlane_i32,
    _readlane_i32,
    atomic_add,
    cast,
    ceildiv,
    copy_warp,
    ld,
    read_clock,
    spin_timed_out,
    st,
    wait_mem_all,
    wave_inclusive_scan,
)
from primus_turbo.flydsl.mega.gfx1250.symm_buffer import BLOCK_M as POOL_BLOCK_M
from primus_turbo.flydsl.mega.gfx1250.symm_buffer import SymBuffer, Workspace
from primus_turbo.flydsl.utils.buffer_ops import (
    buffer_load,
    buffer_store,
    create_buffer_resource_from_addr,
)

_WARP = 64
_BLOCK_THREADS = 512
_PVEC = 8
_NUM_WARPS = _BLOCK_THREADS // _WARP
# fold rows a combine warp pushes per group; their index loads and payload stores overlap
_ROW_UNROLL = 4
# per-warp ceiling on bf16x8 loads in flight in _sum_pool_rows; above it the 8-row sum spills
_MAX_LOADS_IN_FLIGHT = 64
# the combine-only launch's fold rows per wave and group (combine_bf16_tile(pipelined=True)): a 16-row chunk gives
# each of a default workgroup's 8 waves two rows
_PIPELINED_ROW_UNROLL = 2
# per-lane ceiling on the b128 loads of one dispatch_tile_batched copy batch (4 VGPRs each)
_MAX_COPY_LOADS = 64


@ASTRewriter.transform
def spin_until_flag_reaches(
    flag_base: ArithValue,
    flag_idx: fx.Int32,
    expected: fx.Int64,
    scope: str,
    rank: int,
    tag: str,
    drain: bool = True,
):
    """Spin the calling lane until the i64 flag at flag_base[flag_idx] is at least expected.

    ``drain`` first retires the wave's outstanding memory operations; a consumer whose earlier stores do not
    feed the flag (the reduce's previous token) passes False so its first poll does not wait for them."""
    message = f"[MEGA rank={rank} {tag}] flag wait timeout: flag_idx={{}} flag={{}} expected={{}}\n"
    spin_start = read_clock()
    if const_expr(drain):
        wait_mem_all()
    flag = ld(flag_base, flag_idx, scope=scope, dtype=fx.T.i64)
    while flag < expected:
        fx.rocdl.s_sleep(fx.Int32(1))
        if spin_timed_out(spin_start):
            fx.printf(message, flag_idx, flag, expected)
            spin_start = read_clock()
        wait_mem_all()
        flag = ld(flag_base, flag_idx, scope=scope, dtype=fx.T.i64)


def same_rank_order(expert_ids, topk_position, num_experts_per_rank):
    """Return (same_rank_position, num_same_rank_routes) of a valid route among routes to its rank."""
    expert_id = expert_ids[topk_position]
    dst_rank = expert_id // fx.Int32(num_experts_per_rank)
    same_rank_position = fx.Int32(0)
    num_same_rank_routes = fx.Int32(1)
    for other_position, other_expert_id in enumerate(expert_ids):
        if other_position == topk_position:
            continue
        is_same_rank = (other_expert_id >= fx.Int32(0)) & (
            other_expert_id // fx.Int32(num_experts_per_rank) == dst_rank
        )
        # ties break by topk_position so the order stays total
        is_before = (
            other_expert_id <= expert_id if other_position < topk_position else other_expert_id < expert_id
        )
        same_rank_position += arith.select(is_same_rank & is_before, fx.Int32(1), fx.Int32(0))
        num_same_rank_routes += arith.select(is_same_rank, fx.Int32(1), fx.Int32(0))
    return same_rank_position, num_same_rank_routes


def is_primary_route(expert_ids, topk_position, num_experts_per_rank):
    """Return whether the route is first to its rank; only ids < 0 count as invalid, callers bound the top."""
    same_rank_position, _ = same_rank_order(expert_ids, topk_position, num_experts_per_rank)
    return (expert_ids[topk_position] >= fx.Int32(0)) & (same_rank_position == fx.Int32(0))


@ASTRewriter.transform
def dispatch_bf16_tile(
    sym: SymBuffer,
    workspace: Workspace,
    thread_index: fx.Int32,
    block_index: fx.Int32,
    hidden_size: int,
    input_res: ArithValue,
    expert_send_dst_rank_res: ArithValue,
    expert_send_count_res: ArithValue,
    expert_send_offset_res: ArithValue,
    dispatched_token_idx_res: ArithValue,
    dispatch_parity: fx.Int32,
    dispatch_chunk_counter_ptr: ArithValue,
    num_chunks: int,
    num_ranks: int,
    num_experts_per_rank: int,
    rank: int,
    block_threads: int = _BLOCK_THREADS,
    experts_per_publish: int = 1,
):
    """Push this block's chunk of every expert's task to one dst rank, in ascending expert order.

    ``experts_per_publish`` experts share one store retire + barrier before their flags go out (in
    ascending order, so the single-flag wait still holds); it must divide ``num_experts_per_rank``."""
    assert num_experts_per_rank % experts_per_publish == 0, "publish groups tile the local experts"
    hidden_bytes = hidden_size * 2
    assert hidden_bytes % 16 == 0, "hidden*2 must be a multiple of 16 bytes -> hidden % 8 == 0"
    assert block_threads % _WARP == 0, "a block is a whole number of 64-lane copy warps"
    num_warps = block_threads // _WARP
    hidden_i32 = hidden_bytes // 4  # row stride in i32 words
    row_stride = num_chunks * num_warps
    num_max_pool_blocks = int(workspace.num_max_pool_blocks)
    recv_token_base = rank * int(workspace.num_max_tokens_per_rank)
    # hoist workspace-derived values before any dynamic control flow (rewriter can't carry Workspace)
    token_buffer_ptr = workspace.get_dispatch_token_buffer_ptr()
    dispatch_flag_ptr = workspace.get_dispatch_flag_ptr()

    block_dst_rank = block_index % fx.Int32(num_ranks)
    chunk_index = block_index // fx.Int32(num_ranks)
    warp_id = chunk_index * fx.Int32(num_warps) + thread_index // fx.Int32(_WARP)

    # ascending expert order: flag[g] complete implies every expert <= g landed (single-flag wait)
    for expert_group in range(fx.Int32(num_experts_per_rank // experts_per_publish)):
        first_expert = expert_group * fx.Int32(experts_per_publish)
        for local_expert in range(first_expert, first_expert + fx.Int32(experts_per_publish)):
            task_index = local_expert * fx.Int32(num_ranks) + block_dst_rank
            dst_rank = buffer_load(expert_send_dst_rank_res, task_index, vec_width=1, dtype=fx.T.i32)
            source_offset = buffer_load(expert_send_offset_res, task_index, vec_width=1, dtype=fx.T.i32)
            token_count = buffer_load(expert_send_count_res, task_index, vec_width=1, dtype=fx.T.i32)
            token_buffer_address = sym.map(token_buffer_ptr, dst_rank)

            local_count = (token_count - warp_id + fx.Int32(row_stride - 1)) // fx.Int32(row_stride)

            for i in range(local_count):
                token_idx = buffer_load(
                    dispatched_token_idx_res,
                    source_offset + warp_id + i * fx.Int32(row_stride),
                    vec_width=1,
                    dtype=fx.T.i32,
                )
                # dst = peer dispatch_token_buffer row of this recv token, src = local input; offsets in i32 words
                copy_warp(
                    token_buffer_address,
                    input_res,
                    hidden_bytes,
                    dst_off=(fx.Int32(recv_token_base) + token_idx) * fx.Int32(hidden_i32),
                    src_off=token_idx * fx.Int32(hidden_i32),
                    load_cache_modifier=CPOL_DEVICE_STREAM,  # read data produced by the same agent
                    store_cache_modifier=CPOL_SYSTEM_STREAM,
                )

        wait_mem_all()
        fx.gpu.barrier()
        if thread_index == fx.Int32(0):
            for local_expert in range(first_expert, first_expert + fx.Int32(experts_per_publish)):
                task_index = local_expert * fx.Int32(num_ranks) + block_dst_rank
                dst_rank = buffer_load(expert_send_dst_rank_res, task_index, vec_width=1, dtype=fx.T.i32)
                dispatch_flag_address = sym.map(dispatch_flag_ptr, dst_rank)
                # each chunk's stores retired before its counter add, so the last chunk's flag add publishes them all
                chunk_count_before_add = atomic_add(
                    dispatch_chunk_counter_ptr, task_index, fx.Int64(1), scope="agent"
                )
                if chunk_count_before_add == fx.Int64(num_chunks - 1):
                    # the last chunk rearms the counter, so every launch starts from 0 whatever its chunk count
                    st(dispatch_chunk_counter_ptr, task_index, fx.Int64(0), scope="agent")
                    bank = dispatch_parity * fx.Int32(num_max_pool_blocks)
                    atomic_add(dispatch_flag_address, bank + local_expert, fx.Int64(1), scope="sys")


def _pool_row_resource(l2_ptr, pool_row, row_bytes, is_present=True):
    """Buffer resource over one pool row; an absent row gets num_records 0, so its loads read 0 at no cost."""
    base = l2_ptr + cast(pool_row, fx.T.i64) * fx.Int64(row_bytes)
    num_records_bytes = (
        row_bytes if is_present is True else arith.select(is_present, fx.Int32(row_bytes), fx.Int32(0))
    )
    return create_buffer_resource_from_addr(base, num_records_bytes=num_records_bytes)


def _sum_pool_rows(
    pool_rows, l2_ptr, combine_token_res, dst_base, dropped_base, lane_col, hidden, bias=None, warp=_WARP
):
    """Store the f32 sum of the present pool_rows (ascending, -1 absent) as one bf16 row at dst_base.

    ``bias`` = ``(bias_ptr, tile_to_expert_res, weight_res)`` adds each present row's routing weight
    times its expert's bias row, the ``out + b * p`` Megatron applies to an expert's fc2 output."""
    f32_vec = fx.T.vec(_PVEC, fx.T.f32)
    bf16_vec = fx.T.vec(_PVEC, fx.T.bf16)
    row_bytes = hidden * 2
    cols_per_step = warp * _PVEC
    num_full_chunks = hidden // cols_per_step
    tail_cols = hidden % cols_per_step
    row_resources = [_pool_row_resource(l2_ptr, pool_rows[0], row_bytes)]
    safe_rows, presence = [pool_rows[0]], [True]
    for pool_row in pool_rows[1:]:
        is_present = pool_row >= fx.Int32(0)
        safe_row = arith.select(is_present, pool_row, pool_rows[0])
        row_resources.append(_pool_row_resource(l2_ptr, safe_row, row_bytes, is_present))
        safe_rows.append(safe_row)
        presence.append(is_present)
    bias_terms = []
    if bias is not None:
        bias_ptr, tile_to_expert_res, weight_res = bias
        for safe_row, is_present in zip(safe_rows, presence):
            expert = buffer_load(
                tile_to_expert_res, safe_row // fx.Int32(POOL_BLOCK_M), vec_width=1, dtype=fx.T.i32
            )
            weight = buffer_load(weight_res, safe_row, vec_width=1, dtype=fx.T.f32)
            # an absent row's bias resource is empty too, so its term reads 0
            bias_terms.append(
                (
                    _pool_row_resource(bias_ptr, expert, row_bytes, is_present),
                    _vector.broadcast(f32_vec, weight),
                )
            )

    def accumulate(cols):
        sums = [None] * len(cols)
        for row_res in row_resources:
            # read the same-agent GEMM stage
            cpol = CPOL_DEVICE_STREAM
            values = [
                buffer_load(row_res, col, vec_width=_PVEC, dtype=fx.T.bf16, cache_modifier=cpol)
                for col in cols
            ]
            for i, value in enumerate(values):
                term = fx.arith.extf(f32_vec, value)
                sums[i] = term if sums[i] is None else fx.arith.addf(sums[i], term)
        for bias_res, weight in bias_terms:
            values = [buffer_load(bias_res, col, vec_width=_PVEC, dtype=fx.T.bf16) for col in cols]
            for i, value in enumerate(values):
                sums[i] = fx.arith.addf(sums[i], fx.arith.mulf(fx.arith.extf(f32_vec, value), weight))
        return sums

    # passes bound the loads in flight so the sum stays inside the GEMM's VGPR budget
    loads_per_chunk = len(pool_rows) + len(bias_terms)
    num_passes = max(
        1, min(num_full_chunks, ceildiv(loads_per_chunk * num_full_chunks, _MAX_LOADS_IN_FLIGHT))
    )
    chunks_per_pass = max(1, ceildiv(num_full_chunks, num_passes))
    for first_chunk in range(0, num_full_chunks, chunks_per_pass):
        last_chunk = min(first_chunk + chunks_per_pass, num_full_chunks)
        cols = [fx.Int32(chunk * cols_per_step) + lane_col for chunk in range(first_chunk, last_chunk)]
        for col, row_sum in zip(cols, accumulate(cols)):
            # publish to a remote agent
            buffer_store(
                fx.arith.trunc_f(bf16_vec, row_sum),
                combine_token_res,
                dst_base + col,
                cache_modifier=CPOL_SYSTEM_STREAM,
            )
    if tail_cols:
        col = fx.Int32(num_full_chunks * cols_per_step) + lane_col
        is_in_tail = lane_col < fx.Int32(tail_cols)
        row_sum = accumulate([arith.select(is_in_tail, col, fx.Int32(hidden - _PVEC))])[0]
        dst = arith.select(is_in_tail, dst_base + col, dropped_base)
        buffer_store(
            fx.arith.trunc_f(bf16_vec, row_sum), combine_token_res, dst, cache_modifier=CPOL_SYSTEM_STREAM
        )


@ASTRewriter.transform
def combine_bf16_tile(
    sym: SymBuffer,
    workspace: Workspace,
    thread_index: fx.Int32,
    segment_idx: fx.Int32,
    first_fold_row: fx.Int32,
    num_fold_rows: fx.Int32,
    recv_dst_rank_res: ArithValue,
    pool_row_to_route_res: ArithValue,
    pool_row_to_recv_token_res: ArithValue,
    recv_token_to_pool_rows_res: ArithValue,
    l2_ptr: ArithValue,
    epoch: fx.Int64,
    reduce_bank: fx.Int32,
    grad_gate_res: Optional[ArithValue] = None,
    has_grad_gate: bool = False,
    bias: Optional[tuple] = None,
    block_threads: int = _BLOCK_THREADS,
    pipelined: bool = False,
):
    """Push each fold row in [first_fold_row, +num_fold_rows) as its recv token's sum to the primary route.

    ``l2_ptr`` (i64) is this rank's L2 GEMM output, one row per pool row; only this rank reads it.
    ``bias``: the experts' fc2 bias, see :func:`_sum_pool_rows`. ``pipelined`` (the combine-only launch): the row
    sums of :func:`_sum_pool_rows_pipelined`, fold rows in pairs; the fused launch keeps the default."""
    sum_pool_rows = _sum_pool_rows_pipelined if pipelined else _sum_pool_rows
    row_unroll = _PIPELINED_ROW_UNROLL if pipelined else _ROW_UNROLL
    hidden = int(workspace.hidden)
    num_topk = int(workspace.num_topk)
    # A copy warp is one hardware wave: a row's flag goes out after this wave's own stores
    # retire, which on wave32 would not cover a 64-lane warp's other half.
    warp = WAVE
    assert num_topk <= warp, "lane k pushes the grad_gate of pool row k"
    assert block_threads % warp == 0, "a block is a whole number of copy warps"
    num_warps = block_threads // warp
    num_max_routes = int(workspace.num_max_routes)
    row_bytes = hidden * 2
    row_words = hidden // 2
    cols_per_step = warp * _PVEC
    num_full_chunks = hidden // cols_per_step
    tail_cols = hidden % cols_per_step
    warp_id = thread_index // fx.Int32(warp)
    lane_id = thread_index % fx.Int32(warp)
    lane_col = lane_id * fx.Int32(_PVEC)
    dropped_base = fx.Int32(num_max_routes * hidden)

    dst_rank = buffer_load(recv_dst_rank_res, segment_idx, vec_width=1, dtype=fx.T.i32)
    # hoist workspace-derived values before the dynamic loop (rewriter can't carry Workspace)
    combine_token_addr = sym.map(workspace.get_combine_token_buffer_ptr(), dst_rank)
    reduce_flag_addr = sym.map(workspace.get_reduce_flag_ptr(), dst_rank)
    combine_token_res = create_buffer_resource_from_addr(
        combine_token_addr, num_records_bytes=num_max_routes * row_bytes
    )
    combine_gate_res = (
        create_buffer_resource_from_addr(
            sym.map(workspace.get_combine_gate_ptr(), dst_rank), num_records_bytes=num_max_routes * 4
        )
        if has_grad_gate
        else None
    )

    def push_rows(fold_rows):
        # stage each index level for every row first, so the dependent loads overlap across rows
        recv_tokens = [
            buffer_load(pool_row_to_recv_token_res, fold_row, vec_width=1, dtype=fx.T.i32)
            for fold_row in fold_rows
        ]
        pool_rows_per_row = [
            [
                buffer_load(
                    recv_token_to_pool_rows_res,
                    recv_token * fx.Int32(num_topk) + fx.Int32(k),
                    vec_width=1,
                    dtype=fx.T.i32,
                )
                for k in range_constexpr(num_topk)
            ]
            for recv_token in recv_tokens
        ]
        # a fold row is one wave's, so its pool rows are wave-uniform; left in VGPRs, the sum's
        # row descriptors put each load behind a readfirstlane waterfall that drains loadcnt
        pool_rows_per_row = [
            [_readfirstlane_i32(row) for row in pool_rows] for pool_rows in pool_rows_per_row
        ]
        # pool_rows[0] is the primary route's row; the sum lands in that route's combine row
        dst_routes = [
            buffer_load(pool_row_to_route_res, pool_rows[0], vec_width=1, dtype=fx.T.i32)
            for pool_rows in pool_rows_per_row
        ]
        for u in range_constexpr(len(fold_rows)):
            push_payload(fold_rows[u], pool_rows_per_row[u], dst_routes[u])
        # payload and grad_gate stores retire before the flags that topk_reduce_bf16_tile waits on
        wait_mem_all()
        for u in range_constexpr(len(fold_rows)):
            st(reduce_flag_addr, reduce_bank + dst_routes[u], epoch, scope="sys")

    def push_payload(fold_row, pool_rows, dst_route):
        dst_base = dst_route * fx.Int32(hidden)
        if const_expr(bias is not None):
            # a bias term rides the sum, so with one the single-row copy has nothing to offer
            sum_pool_rows(
                pool_rows, l2_ptr, combine_token_res, dst_base, dropped_base, lane_col, hidden, bias, warp
            )
        else:
            push_rows_sum(fold_row, pool_rows, dst_route, dst_base)
        if const_expr(has_grad_gate):
            # lane k pushes the grad_gate of pool_rows[k] to that row's own route
            lane_pool_row = pool_rows[0]
            for k in range_constexpr(1, num_topk):
                lane_pool_row = arith.select(lane_id == fx.Int32(k), pool_rows[k], lane_pool_row)
            is_gate_lane = (lane_id < fx.Int32(num_topk)) & (lane_pool_row >= fx.Int32(0))
            gate_row = arith.select(is_gate_lane, lane_pool_row, pool_rows[0])
            gate_value = buffer_load(grad_gate_res, gate_row, vec_width=1, dtype=fx.T.f32)
            gate_route = buffer_load(pool_row_to_route_res, gate_row, vec_width=1, dtype=fx.T.i32)
            gate_dst = arith.select(is_gate_lane, gate_route, fx.Int32(num_max_routes))
            buffer_store(gate_value, combine_gate_res, gate_dst, cache_modifier=CPOL_SYSTEM_STREAM)

    def push_rows_sum(fold_row, pool_rows, dst_route, dst_base):
        second_pool_row = pool_rows[1] if num_topk > 1 else fx.Int32(-1)
        if second_pool_row < fx.Int32(0):
            copy_warp(
                combine_token_addr,
                # i64 row base: fold_row * row_words overflows i32 on large pools
                l2_ptr + cast(fold_row, fx.T.i64) * fx.Int64(row_bytes),
                num_full_chunks * cols_per_step * 2,
                dst_off=dst_route * fx.Int32(row_words),
                load_cache_modifier=CPOL_DEVICE_STREAM,  # read the same-agent GEMM stage
                store_cache_modifier=CPOL_SYSTEM_STREAM,  # publish to a remote agent
                warp=warp,
            )
            if const_expr(tail_cols):
                col = fx.Int32(num_full_chunks * cols_per_step) + lane_col
                is_in_tail = lane_col < fx.Int32(tail_cols)
                fold_row_res = _pool_row_resource(l2_ptr, fold_row, row_bytes)
                safe_col = arith.select(is_in_tail, col, fx.Int32(hidden - _PVEC))
                tail_value = buffer_load(
                    fold_row_res,
                    safe_col,
                    vec_width=_PVEC,
                    dtype=fx.T.bf16,
                    cache_modifier=CPOL_DEVICE_STREAM,
                )
                dst = arith.select(is_in_tail, dst_base + col, dropped_base)
                buffer_store(tail_value, combine_token_res, dst, cache_modifier=CPOL_SYSTEM_STREAM)
        else:
            sum_pool_rows(
                pool_rows, l2_ptr, combine_token_res, dst_base, dropped_base, lane_col, hidden, warp=warp
            )

    local_count = (num_fold_rows - warp_id + fx.Int32(num_warps - 1)) // fx.Int32(num_warps)
    num_grouped = (local_count // fx.Int32(row_unroll)) * fx.Int32(row_unroll)
    for i in range(0, num_grouped, row_unroll):
        push_rows(
            [
                first_fold_row + warp_id + (i + fx.Int32(u)) * fx.Int32(num_warps)
                for u in range_constexpr(row_unroll)
            ]
        )
    for i in range(num_grouped, local_count):
        push_rows([first_fold_row + warp_id + i * fx.Int32(num_warps)])


def _steps(first: int, count: int, end: int) -> list:
    return list(range(first, min(first + count, end)))


@ASTRewriter.transform
def topk_reduce_bf16_tile(
    thread_index: fx.Int32,
    reduce_block_idx: fx.Int32,
    num_reduce_warps: int,
    num_topk: int,
    hidden: int,
    num_experts: int,
    num_experts_per_rank: int,
    num_max_routes: int,
    rank: int,
    combine_token_res: ArithValue,
    output_res: ArithValue,
    topk_indices_res: ArithValue,
    num_tokens_res: ArithValue,
    reduce_flag_base: ArithValue,
    reduce_bank: fx.Int32,
    epoch: fx.Int64,
    combine_gate_res: Optional[ArithValue] = None,
    grad_topk_weights_res: Optional[ArithValue] = None,
    has_grad_gate: bool = False,
    block_threads: int = _BLOCK_THREADS,
    vec_unroll: int = 1,
):
    """Sum each token's primary-route combine rows into its output row once their reduce flags reach epoch.

    ``vec_unroll`` > 1 issues the loads of that many 64-lane column steps before summing any, so
    a warp keeps more of the row in flight; 1 is the one-step-at-a-time loop."""
    f32_vec = fx.T.vec(_PVEC, fx.T.f32)
    bf16_vec = fx.T.vec(_PVEC, fx.T.bf16)
    num_vec_chunks = hidden // _PVEC
    lane_id = thread_index % fx.Int32(_WARP)
    warp_id = thread_index // fx.Int32(_WARP)
    num_tokens = buffer_load(num_tokens_res, fx.Int32(rank), vec_width=1, dtype=fx.T.i32)
    token = reduce_block_idx * fx.Int32(block_threads // _WARP) + warp_id
    # A 64-lane copy warp is two waves; each wave's own first lane waits for the flags
    # (a workgroup barrier would pair with another warp whose token count differs).
    hw_wave = WAVE
    is_wave_leader = thread_index % fx.Int32(hw_wave) == fx.Int32(0)
    while token < num_tokens:
        route_base = token * fx.Int32(num_topk)
        expert_ids = []
        for j in range_constexpr(num_topk):
            expert_id = buffer_load(topk_indices_res, route_base + fx.Int32(j), vec_width=1, dtype=fx.T.i64)
            is_valid = (expert_id >= fx.Int64(0)) & (expert_id < fx.Int64(num_experts))
            expert_ids.append(arith.select(is_valid, cast(expert_id, fx.T.i32), fx.Int32(-1)))
        is_primary = [is_primary_route(expert_ids, j, num_experts_per_rank) for j in range(num_topk)]
        for j in range_constexpr(num_topk):
            if is_primary[j]:
                if is_wave_leader:
                    spin_until_flag_reaches(
                        reduce_flag_base, reduce_bank + route_base + fx.Int32(j), epoch, "sys", rank, "reduce"
                    )
        # a non-primary route points past num_records, so its load reads 0 and moves no bytes
        route_offsets = [
            arith.select(
                is_primary[j],
                (route_base + fx.Int32(j)) * fx.Int32(hidden),
                fx.Int32(num_max_routes * hidden),
            )
            for j in range(num_topk)
        ]
        if const_expr(vec_unroll > 1):
            num_steps = ceildiv(num_vec_chunks, _WARP)
            for first_step in range_constexpr(0, num_steps, vec_unroll):
                vec_ids = [
                    lane_id + fx.Int32(step * _WARP) for step in _steps(first_step, vec_unroll, num_steps)
                ]
                # a lane past the row's last chunk reads chunk 0 and skips its store
                cols = [
                    arith.select(v < fx.Int32(num_vec_chunks), v * fx.Int32(_PVEC), fx.Int32(0))
                    for v in vec_ids
                ]
                values = [
                    [
                        buffer_load(
                            combine_token_res,
                            route_offsets[j] + col,
                            vec_width=_PVEC,
                            dtype=fx.T.bf16,
                            cache_modifier=CPOL_SYSTEM_STREAM,  # system-visible non-temporal read
                        )
                        for j in range_constexpr(num_topk)
                    ]
                    for col in cols
                ]
                for u in range_constexpr(len(vec_ids)):
                    row_sum = fx.arith.extf(f32_vec, values[u][0])
                    for j in range_constexpr(1, num_topk):
                        row_sum = fx.arith.addf(row_sum, fx.arith.extf(f32_vec, values[u][j]))
                    if vec_ids[u] < fx.Int32(num_vec_chunks):
                        buffer_store(
                            fx.arith.trunc_f(bf16_vec, row_sum),
                            output_res,
                            token * fx.Int32(hidden) + cols[u],
                        )
        else:
            vec_idx = lane_id
            while vec_idx < fx.Int32(num_vec_chunks):
                col = vec_idx * fx.Int32(_PVEC)
                row_sum = None
                for j in range_constexpr(num_topk):
                    value = buffer_load(
                        combine_token_res,
                        route_offsets[j] + col,
                        vec_width=_PVEC,
                        dtype=fx.T.bf16,
                        cache_modifier=CPOL_SYSTEM_STREAM,  # system-visible non-temporal read
                    )
                    term = fx.arith.extf(f32_vec, value)
                    row_sum = term if row_sum is None else fx.arith.addf(row_sum, term)
                buffer_store(fx.arith.trunc_f(bf16_vec, row_sum), output_res, token * fx.Int32(hidden) + col)
                vec_idx = vec_idx + fx.Int32(_WARP)
        if const_expr(has_grad_gate):
            # every valid route's dst has a primary route whose flag was awaited above
            for j in range_constexpr(num_topk):
                if lane_id == fx.Int32(0):
                    gate_value = buffer_load(
                        combine_gate_res,
                        route_base + fx.Int32(j),
                        vec_width=1,
                        dtype=fx.T.f32,
                        cache_modifier=CPOL_SYSTEM_STREAM,
                    )
                    is_valid = expert_ids[j] >= fx.Int32(0)
                    gate_value = arith.select(is_valid, gate_value, fx.Float32(0.0))
                    buffer_store(gate_value, grad_topk_weights_res, route_base + fx.Int32(j))
        token = token + fx.Int32(num_reduce_warps)


# ---- the dispatch-only and combine-only launches' comm roles ----
# They run on a grid of their own, with no GEMM tile to overlap: the batched dispatch and the pipelined combine
# and packed reduce below. The fused dispatch + L1 GEMM and L2 GEMM + combine launches keep the roles above,
# which share the GPU with the GEMM tiles better.


@ASTRewriter.transform
def block_exclusive_scan_lds(
    thread_index: fx.Int32,
    block_threads: int,
    lds_base: ArithValue,
    wave_total_word: int,
    prefix_word: int,
    num_items: int,
    load_item,
):
    """Exclusive prefix sum over ``num_items`` items into LDS, lane-parallel: ``load_item(item, is_item)`` gives
    item ``item``'s i32 count (ignored past ``num_items``) and ``[(lds_word, value), ...]`` to store at
    ``lds_word + item``; the prefix lands at ``prefix_word + item`` and the total at ``prefix_word + num_items``.
    Items go a block-sized page at a time (a wave scan, then the waves' totals through ``block_threads / WAVE``
    scratch words at ``wave_total_word``). Every thread of the block calls it; it ends on a barrier."""
    num_waves = block_threads // WAVE
    lane = thread_index % fx.Int32(WAVE)
    wave = thread_index // fx.Int32(WAVE)
    carry = fx.Int32(0)
    for page in range_constexpr(ceildiv(num_items, block_threads)):
        item = fx.Int32(page * block_threads) + thread_index
        is_item = item < fx.Int32(num_items)
        count, extras = load_item(item, is_item)
        count = arith.select(is_item, count, fx.Int32(0))
        inclusive = wave_inclusive_scan(count)
        if lane == fx.Int32(WAVE - 1):
            st(lds_base, fx.Int32(wave_total_word) + wave, inclusive, scope="workgroup", space=3)
        fx.gpu.barrier()
        before_wave = fx.Int32(0)
        page_total = fx.Int32(0)
        for w in range_constexpr(num_waves):
            wave_total = ld(lds_base, fx.Int32(wave_total_word + w), scope="workgroup", space=3)
            before_wave = before_wave + arith.select(wave > fx.Int32(w), wave_total, fx.Int32(0))
            page_total = page_total + wave_total
        exclusive = carry + before_wave + inclusive - count
        if is_item:
            st(lds_base, fx.Int32(prefix_word) + item, exclusive, scope="workgroup", space=3)
            for k in range_constexpr(len(extras)):
                st(lds_base, fx.Int32(extras[k][0]) + item, extras[k][1], scope="workgroup", space=3)
        carry = carry + page_total
        fx.gpu.barrier()  # the wave totals are rewritten by the next page
    if thread_index == fx.Int32(0):
        st(lds_base, fx.Int32(prefix_word + num_items), carry, scope="workgroup", space=3)
    fx.gpu.barrier()


def dispatch_table_lds_words(num_experts_per_rank: int, block_threads: int = _BLOCK_THREADS) -> int:
    """i32 words of LDS :func:`dispatch_tile_batched` takes at ``lds_base``: per-wave scan totals, the exclusive prefix
    of the tasks' token counts plus their total, and each task's offset in ``dispatched_token_idx``."""
    return block_threads // WAVE + 2 * num_experts_per_rank + 1


def _wave_copy_offsets(nbytes: int):
    """i32-word (load, store) offsets of this lane's b128 pieces of an ``nbytes`` row copied by one hardware wave;
    idle lanes of a ragged tail read word 0 and store one row past the end, where a row-sized destination drops it."""
    assert nbytes % (_COPY_VEC_I32 * 4) == 0, "rows are whole 16-byte words"
    cols = WAVE * _COPY_VEC_I32  # i32 words one wave instruction moves
    row_words = nbytes // 4
    num_full = row_words // cols
    tail_words = row_words - num_full * cols
    lane_off = (fx.Int32(fx.thread_idx.x) % fx.Int32(WAVE)) * fx.Int32(_COPY_VEC_I32)
    offsets = [fx.Int32(c * cols) + lane_off for c in range_constexpr(num_full)]
    load_offsets, store_offsets = list(offsets), list(offsets)
    if tail_words:
        in_tail = lane_off < fx.Int32(tail_words)
        tail_off = fx.Int32(num_full * cols) + lane_off
        load_offsets.append(arith.select(in_tail, tail_off, fx.Int32(0)))
        store_offsets.append(arith.select(in_tail, tail_off, fx.Int32(row_words)))
    return load_offsets, store_offsets


def _copy_rows(rows, load_cache_modifier: int, store_cache_modifier: int) -> None:
    """Copy rows with one hardware wave, every row's loads issued before the first store so their round trips
    overlap. ``rows``: ``(src_res, src_word_offset, dst_address_i64, nbytes, is_valid)``; an invalid row's stores
    are dropped (its destination holds no records), so its source offset need only be in bounds."""
    offsets = {nbytes: _wave_copy_offsets(nbytes) for _, _, _, nbytes, _ in rows}
    values = [
        [
            buffer_load(
                src_res,
                src_off + o,
                vec_width=_COPY_VEC_I32,
                dtype=fx.T.i32,
                cache_modifier=load_cache_modifier,
            )
            for o in offsets[nbytes][0]
        ]
        for src_res, src_off, _, nbytes, _ in rows
    ]
    for (_, _, dst_address, nbytes, is_valid), row_values in zip(rows, values):
        dst_res = create_buffer_resource_from_addr(
            dst_address, num_records_bytes=arith.select(is_valid, fx.Int32(nbytes), fx.Int32(0))
        )
        for o, v in zip(offsets[nbytes][1], row_values):
            buffer_store(v, dst_res, o, cache_modifier=store_cache_modifier)


def _last_expert_at_or_before(lds_base, lds_prefix: int, first_expert, num_experts: int, flat):
    """Per lane, the last expert of ``[first_expert, + num_experts)`` whose LDS prefix entry is <= ``flat`` (a
    branchless binary search; the first expert's entry must be <= ``flat``)."""
    expert = first_expert
    span = num_experts
    while span > 1:
        half = span // 2
        probe = expert + fx.Int32(half)
        probe_start = ld(lds_base, fx.Int32(lds_prefix) + probe, scope="workgroup", space=3)
        expert = arith.select(probe_start <= flat, probe, expert)
        span -= half
    return expert


@ASTRewriter.transform
def dispatch_tile_batched(
    sym: SymBuffer,
    workspace: Workspace,
    thread_index: fx.Int32,
    block_index: fx.Int32,
    hidden_size: int,
    input_res: ArithValue,
    expert_send_dst_rank_res: ArithValue,
    expert_send_count_res: ArithValue,
    expert_send_offset_res: ArithValue,
    dispatched_token_idx_res: ArithValue,
    dispatch_parity: fx.Int32,
    dispatch_chunk_counter_ptr: ArithValue,
    num_chunks: int,
    num_ranks: int,
    num_experts_per_rank: int,
    rank: int,
    lds_base: ArithValue,
    block_threads: int = _BLOCK_THREADS,
    experts_per_publish: int = 1,
    scale_res: Optional[ArithValue] = None,
):
    """Push this block's share of every expert task's tokens to one dst rank, publish group by publish group.

    A publish group is ``experts_per_publish`` consecutive local experts (it must divide ``num_experts_per_rank``):
    the block pushes the group's tokens, retires its stores, then adds one to the group's chunk counter (the counter
    of the group's first task); the last of the dst rank's ``num_chunks`` blocks to do so rearms that counter and
    bumps the dst rank's flag of every expert in the group. Groups go in ascending expert order, so an expert's flag
    at its epoch implies every lower expert landed too (the single-flag wait of the GEMM tiles).

    The tasks' counts and offsets are read once, lane-parallel, into an exclusive-prefix table in LDS (``lds_base``,
    :func:`dispatch_table_lds_words` words). A group's tokens are then one flat range that the dst rank's copy
    waves (``num_chunks * block_threads / WAVE`` hardware waves) stride over: a wave resolves up to WAVE of its
    tokens with one index load per lane and copies them in batches that keep up to ``_MAX_COPY_LOADS`` b128 loads
    per lane in flight.

    With ``scale_res`` the tokens are MXFP8: ``input_res`` holds E4M3 rows of ``hidden_size`` bytes and
    ``scale_res`` their raw E8M0 scale rows (``hidden_size / 32`` bytes); they land in the dispatch token buffer's
    fp8 view (``SymmBuffer.dispatch_fp8_views``: the rows, then their scale rows after ``num_max_recv_tokens`` of
    them)."""
    assert num_experts_per_rank % experts_per_publish == 0, "publish groups tile the local experts"
    mx = scale_res is not None
    hidden_bytes = hidden_size * (1 if mx else 2)
    assert hidden_bytes % 16 == 0, "a token row is whole 16-byte words"
    assert not mx or hidden_size % 512 == 0, "an E8M0 scale row is whole 16-byte words: hidden % 512 == 0"
    assert block_threads % WAVE == 0, "a block is a whole number of copy waves"
    num_waves = block_threads // WAVE
    row_stride = num_chunks * num_waves  # copy waves per dst rank
    scale_bytes = hidden_size // 32 if const_expr(mx) else 0  # an E8M0 scale row
    loads_per_row = ceildiv(hidden_bytes, WAVE * _COPY_VEC_I32 * 4) + (1 if mx else 0)
    rows_per_batch = max(1, _MAX_COPY_LOADS // loads_per_row)
    num_max_pool_blocks = int(workspace.num_max_pool_blocks)
    recv_token_base = rank * int(workspace.num_max_tokens_per_rank)
    # hoist workspace-derived values before any dynamic control flow (rewriter can't carry Workspace)
    token_buffer_ptr = workspace.get_dispatch_token_buffer_ptr()
    # the scale plane follows the receive rows (``SymmBuffer.dispatch_fp8_views``)
    scale_buffer_ptr = (
        token_buffer_ptr + int(workspace.num_max_recv_tokens) * hidden_size if const_expr(mx) else None
    )
    dispatch_flag_ptr = workspace.get_dispatch_flag_ptr()
    # LDS words: [0, num_waves) scan scratch, then the prefix (one per expert + the total), then the offsets
    lds_prefix = num_waves
    lds_source_offset = num_waves + num_experts_per_rank + 1

    lane = thread_index % fx.Int32(WAVE)
    wave = thread_index // fx.Int32(WAVE)
    block_dst_rank = block_index % fx.Int32(num_ranks)
    wave_id = (block_index // fx.Int32(num_ranks)) * fx.Int32(num_waves) + wave

    # task = local expert * num_ranks + dst rank: this block's tasks share one dst rank, read off its first task
    dst_rank = _readfirstlane_i32(
        buffer_load(expert_send_dst_rank_res, block_dst_rank, vec_width=1, dtype=fx.T.i32)
    )
    token_buffer_address = sym.map(token_buffer_ptr, dst_rank)
    scale_buffer_address = sym.map(scale_buffer_ptr, dst_rank) if const_expr(mx) else None
    dispatch_flag_address = sym.map(dispatch_flag_ptr, dst_rank)

    def load_task(expert, is_expert):
        task_index = arith.select(is_expert, expert, fx.Int32(0)) * fx.Int32(num_ranks) + block_dst_rank
        task_count = buffer_load(expert_send_count_res, task_index, vec_width=1, dtype=fx.T.i32)
        source_offset = buffer_load(expert_send_offset_res, task_index, vec_width=1, dtype=fx.T.i32)
        return task_count, [(lds_source_offset, source_offset)]

    # the send table, read once: the tasks' token counts as an exclusive prefix, and their source offsets
    block_exclusive_scan_lds(
        thread_index, block_threads, lds_base, 0, lds_prefix, num_experts_per_rank, load_task
    )

    for group in range(fx.Int32(num_experts_per_rank // experts_per_publish)):
        first_expert = group * fx.Int32(experts_per_publish)
        group_start = _readfirstlane_i32(
            ld(lds_base, fx.Int32(lds_prefix) + first_expert, scope="workgroup", space=3)
        )
        group_end = _readfirstlane_i32(
            ld(
                lds_base,
                fx.Int32(lds_prefix + experts_per_publish) + first_expert,
                scope="workgroup",
                space=3,
            )
        )
        # this wave's tokens of the group: flat positions group_start + wave_id + k * row_stride
        num_rows = (group_end - group_start - wave_id + fx.Int32(row_stride - 1)) // fx.Int32(row_stride)
        for round_start in range(fx.Int32(0), num_rows, fx.Int32(WAVE)):
            # lane l resolves the wave's row round_start + l: its expert is the last one whose prefix is <= its
            # flat position (binary search over the group), its token the task's dispatched_token_idx entry
            row = round_start + lane
            flat = group_start + wave_id + row * fx.Int32(row_stride)
            expert = _last_expert_at_or_before(lds_base, lds_prefix, first_expert, experts_per_publish, flat)
            expert_start = ld(lds_base, fx.Int32(lds_prefix) + expert, scope="workgroup", space=3)
            source_offset = ld(lds_base, fx.Int32(lds_source_offset) + expert, scope="workgroup", space=3)
            source_position = source_offset + flat - expert_start
            token_of_lane = buffer_load(
                dispatched_token_idx_res,
                arith.select(row < num_rows, source_position, fx.Int32(0)),
                vec_width=1,
                dtype=fx.T.i32,
            )
            round_rows = arith.select(
                num_rows - round_start < fx.Int32(WAVE), num_rows - round_start, fx.Int32(WAVE)
            )
            for batch_start in range(fx.Int32(0), round_rows, fx.Int32(rows_per_batch)):
                copies = []
                for u in range_constexpr(rows_per_batch):
                    is_valid = batch_start + fx.Int32(u) < round_rows
                    # an idle slot copies token 0 (the batch's first slot is always a real row) into nothing
                    token = arith.select(
                        is_valid, _readlane_i32(token_of_lane, batch_start + fx.Int32(u)), fx.Int32(0)
                    )
                    recv_row = cast(fx.Int32(recv_token_base) + token, fx.T.i64)
                    copies.append(
                        (
                            input_res,
                            token * fx.Int32(hidden_bytes // 4),
                            token_buffer_address + recv_row * fx.Int64(hidden_bytes),
                            hidden_bytes,
                            is_valid,
                        )
                    )
                    if const_expr(mx):
                        copies.append(
                            (
                                scale_res,
                                token * fx.Int32(scale_bytes // 4),
                                scale_buffer_address + recv_row * fx.Int64(scale_bytes),
                                scale_bytes,
                                is_valid,
                            )
                        )
                # read data produced by the same agent; publish to a remote agent
                _copy_rows(copies, CPOL_DEVICE_STREAM, CPOL_SYSTEM_STREAM)

        wait_mem_all()
        fx.gpu.barrier()
        if thread_index == fx.Int32(0):
            counter_index = first_expert * fx.Int32(num_ranks) + block_dst_rank
            # each chunk's stores retired before its counter add, so the last chunk's flag adds publish them all
            chunk_count_before_add = atomic_add(
                dispatch_chunk_counter_ptr, counter_index, fx.Int64(1), scope="agent"
            )
            if chunk_count_before_add == fx.Int64(num_chunks - 1):
                # the last chunk rearms the counter, so every launch starts from 0 whatever its chunk count
                st(dispatch_chunk_counter_ptr, counter_index, fx.Int64(0), scope="agent")
                bank = dispatch_parity * fx.Int32(num_max_pool_blocks)
                for local_expert in range(first_expert, first_expert + fx.Int32(experts_per_publish)):
                    atomic_add(dispatch_flag_address, bank + local_expert, fx.Int64(1), scope="sys")


def _sum_pool_rows_pipelined(
    pool_rows, l2_ptr, combine_token_res, dst_base, dropped_base, lane_col, hidden, bias=None, warp=_WARP
):
    """Store the f32 sum of the present pool_rows (ascending, -1 absent) as one bf16 row at dst_base.

    ``bias`` = ``(bias_ptr, tile_to_expert_res, weight_res)`` adds each present row's routing weight
    times its expert's bias row, the ``out + b * p`` Megatron applies to an expert's fc2 output."""
    f32_vec = fx.T.vec(_PVEC, fx.T.f32)
    bf16_vec = fx.T.vec(_PVEC, fx.T.bf16)
    row_bytes = hidden * 2
    cols_per_step = warp * _PVEC
    num_full_chunks = hidden // cols_per_step
    tail_cols = hidden % cols_per_step
    row_resources = [_pool_row_resource(l2_ptr, pool_rows[0], row_bytes)]
    safe_rows, presence = [pool_rows[0]], [True]
    for pool_row in pool_rows[1:]:
        is_present = pool_row >= fx.Int32(0)
        safe_row = arith.select(is_present, pool_row, pool_rows[0])
        row_resources.append(_pool_row_resource(l2_ptr, safe_row, row_bytes, is_present))
        safe_rows.append(safe_row)
        presence.append(is_present)
    bias_terms = []
    if bias is not None:
        bias_ptr, tile_to_expert_res, weight_res = bias
        for safe_row, is_present in zip(safe_rows, presence):
            expert = buffer_load(
                tile_to_expert_res, safe_row // fx.Int32(POOL_BLOCK_M), vec_width=1, dtype=fx.T.i32
            )
            weight = buffer_load(weight_res, safe_row, vec_width=1, dtype=fx.T.f32)
            # an absent row's bias resource is empty too, so its term reads 0
            bias_terms.append(
                (
                    _pool_row_resource(bias_ptr, expert, row_bytes, is_present),
                    _vector.broadcast(f32_vec, weight),
                )
            )

    def accumulate(cols):
        # every load of the pass goes out before the first add: emitted row by row between the adds, the
        # loads left one row at a time, a round trip per row. The adds keep the row order of the sum.
        row_values = [
            # read the same-agent GEMM stage
            [
                buffer_load(row_res, col, vec_width=_PVEC, dtype=fx.T.bf16, cache_modifier=CPOL_DEVICE_STREAM)
                for col in cols
            ]
            for row_res in row_resources
        ]
        bias_values = [
            [buffer_load(bias_res, col, vec_width=_PVEC, dtype=fx.T.bf16) for col in cols]
            for bias_res, _ in bias_terms
        ]
        sums = []
        for i in range(len(cols)):
            row_sum = fx.arith.extf(f32_vec, row_values[0][i])
            for values in row_values[1:]:
                row_sum = fx.arith.addf(row_sum, fx.arith.extf(f32_vec, values[i]))
            for (_, weight), values in zip(bias_terms, bias_values):
                row_sum = fx.arith.addf(row_sum, fx.arith.mulf(fx.arith.extf(f32_vec, values[i]), weight))
            sums.append(row_sum)
        return sums

    # passes bound the loads in flight so the sum stays inside the GEMM's VGPR budget
    loads_per_chunk = len(pool_rows) + len(bias_terms)
    num_passes = max(
        1, min(num_full_chunks, ceildiv(loads_per_chunk * num_full_chunks, _MAX_LOADS_IN_FLIGHT))
    )
    chunks_per_pass = max(1, ceildiv(num_full_chunks, num_passes))
    for first_chunk in range(0, num_full_chunks, chunks_per_pass):
        last_chunk = min(first_chunk + chunks_per_pass, num_full_chunks)
        cols = [fx.Int32(chunk * cols_per_step) + lane_col for chunk in range(first_chunk, last_chunk)]
        for col, row_sum in zip(cols, accumulate(cols)):
            # publish to a remote agent
            buffer_store(
                fx.arith.trunc_f(bf16_vec, row_sum),
                combine_token_res,
                dst_base + col,
                cache_modifier=CPOL_SYSTEM_STREAM,
            )
    if tail_cols:
        col = fx.Int32(num_full_chunks * cols_per_step) + lane_col
        is_in_tail = lane_col < fx.Int32(tail_cols)
        row_sum = accumulate([arith.select(is_in_tail, col, fx.Int32(hidden - _PVEC))])[0]
        dst = arith.select(is_in_tail, dst_base + col, dropped_base)
        buffer_store(
            fx.arith.trunc_f(bf16_vec, row_sum), combine_token_res, dst, cache_modifier=CPOL_SYSTEM_STREAM
        )


def _pack_primary_routes(is_primary, route_base, hidden: int, num_slots: int, num_max_routes: int):
    """Row offsets of a token's primary routes packed in route order into ``num_slots`` slots (an empty slot points
    past num_records, so it reads 0 and moves no bytes), and whether the token has a non-primary route."""
    absent = fx.Int32(num_max_routes * hidden)
    slots = [absent] * num_slots
    num_primary = fx.Int32(0)
    for j, primary in enumerate(is_primary):
        offset = (route_base + fx.Int32(j)) * fx.Int32(hidden)
        for slot in range(num_slots):
            slots[slot] = arith.select(primary & (num_primary == fx.Int32(slot)), offset, slots[slot])
        num_primary = num_primary + arith.select(primary, fx.Int32(1), fx.Int32(0))
    return slots, num_primary < fx.Int32(len(is_primary))


@ASTRewriter.transform
def topk_reduce_tile_packed(
    thread_index: fx.Int32,
    reduce_block_idx: fx.Int32,
    num_reduce_warps: int,
    num_topk: int,
    hidden: int,
    num_experts: int,
    num_experts_per_rank: int,
    num_max_routes: int,
    rank: int,
    combine_token_res: ArithValue,
    output_res: ArithValue,
    topk_indices_res: ArithValue,
    num_tokens_res: ArithValue,
    reduce_flag_base: ArithValue,
    reduce_bank: fx.Int32,
    epoch: fx.Int64,
    combine_gate_res: Optional[ArithValue] = None,
    grad_topk_weights_res: Optional[ArithValue] = None,
    has_grad_gate: bool = False,
    block_threads: int = _BLOCK_THREADS,
    vec_unroll: int = 1,
    num_route_slots: int = 0,
):
    """Sum each token's primary-route combine rows into its output row once their reduce flags reach epoch.

    ``vec_unroll`` > 1 issues the loads of that many 64-lane column steps before summing any, so
    a warp keeps more of the row in flight; 1 is the one-step-at-a-time loop.

    ``num_route_slots`` > 0 packs the token's primary routes (one per rank holding its experts, so
    ``min(num_topk, num_ranks)`` slots always suffice) into that many slots before loading: a column step
    loads one row per slot instead of one per route. The sum is the route-order sum bit for bit: the absent
    routes' zero rows only turned a -0.0 partial sum into +0.0, which one +0.0 added at the end redoes."""
    f32_vec = fx.T.vec(_PVEC, fx.T.f32)
    bf16_vec = fx.T.vec(_PVEC, fx.T.bf16)
    num_vec_chunks = hidden // _PVEC
    lane_id = thread_index % fx.Int32(_WARP)
    warp_id = thread_index // fx.Int32(_WARP)
    num_tokens = buffer_load(num_tokens_res, fx.Int32(rank), vec_width=1, dtype=fx.T.i32)
    token = reduce_block_idx * fx.Int32(block_threads // _WARP) + warp_id
    # A 64-lane copy warp is two waves; each wave's own first lane waits for the flags
    # (a workgroup barrier would pair with another warp whose token count differs).
    hw_wave = WAVE
    is_wave_leader = thread_index % fx.Int32(hw_wave) == fx.Int32(0)
    assert not has_grad_gate or num_topk <= hw_wave, "lane j of the first wave moves route j's gate gradient"
    plus_zero = (
        _vector.broadcast(f32_vec, fx.arith.constant(0.0)) if const_expr(num_route_slots > 0) else None
    )
    while token < num_tokens:
        route_base = token * fx.Int32(num_topk)
        expert_ids = []
        for j in range_constexpr(num_topk):
            expert_id = buffer_load(topk_indices_res, route_base + fx.Int32(j), vec_width=1, dtype=fx.T.i64)
            is_valid = (expert_id >= fx.Int64(0)) & (expert_id < fx.Int64(num_experts))
            expert_ids.append(arith.select(is_valid, cast(expert_id, fx.T.i32), fx.Int32(-1)))
        is_primary = [is_primary_route(expert_ids, j, num_experts_per_rank) for j in range(num_topk)]
        for j in range_constexpr(num_topk):
            if is_primary[j]:
                if is_wave_leader:
                    # the previous token's output stores feed no flag: the first poll need not wait for them
                    spin_until_flag_reaches(
                        reduce_flag_base,
                        reduce_bank + route_base + fx.Int32(j),
                        epoch,
                        "sys",
                        rank,
                        "reduce",
                        drain=num_route_slots == 0,
                    )
        if const_expr(num_route_slots > 0):
            route_offsets, has_absent_route = _pack_primary_routes(
                is_primary, route_base, hidden, num_route_slots, num_max_routes
            )
        else:
            # a non-primary route points past num_records, so its load reads 0 and moves no bytes
            route_offsets = [
                arith.select(
                    is_primary[j],
                    (route_base + fx.Int32(j)) * fx.Int32(hidden),
                    fx.Int32(num_max_routes * hidden),
                )
                for j in range(num_topk)
            ]
        num_rows = len(route_offsets)
        if const_expr(vec_unroll > 1):
            num_steps = ceildiv(num_vec_chunks, _WARP)
            for first_step in range_constexpr(0, num_steps, vec_unroll):
                vec_ids = [
                    lane_id + fx.Int32(step * _WARP) for step in _steps(first_step, vec_unroll, num_steps)
                ]
                # a lane past the row's last chunk reads chunk 0 and skips its store
                cols = [
                    arith.select(v < fx.Int32(num_vec_chunks), v * fx.Int32(_PVEC), fx.Int32(0))
                    for v in vec_ids
                ]
                values = [
                    [
                        buffer_load(
                            combine_token_res,
                            route_offsets[j] + col,
                            vec_width=_PVEC,
                            dtype=fx.T.bf16,
                            cache_modifier=CPOL_SYSTEM_STREAM,  # system-visible non-temporal read
                        )
                        for j in range_constexpr(num_rows)
                    ]
                    for col in cols
                ]
                for u in range_constexpr(len(vec_ids)):
                    row_sum = fx.arith.extf(f32_vec, values[u][0])
                    for j in range_constexpr(1, num_rows):
                        row_sum = fx.arith.addf(row_sum, fx.arith.extf(f32_vec, values[u][j]))
                    if const_expr(num_route_slots > 0):
                        row_sum = arith.select(has_absent_route, fx.arith.addf(row_sum, plus_zero), row_sum)
                    if vec_ids[u] < fx.Int32(num_vec_chunks):
                        buffer_store(
                            fx.arith.trunc_f(bf16_vec, row_sum),
                            output_res,
                            token * fx.Int32(hidden) + cols[u],
                        )
        else:
            vec_idx = lane_id
            while vec_idx < fx.Int32(num_vec_chunks):
                col = vec_idx * fx.Int32(_PVEC)
                row_sum = None
                for j in range_constexpr(num_rows):
                    value = buffer_load(
                        combine_token_res,
                        route_offsets[j] + col,
                        vec_width=_PVEC,
                        dtype=fx.T.bf16,
                        cache_modifier=CPOL_SYSTEM_STREAM,  # system-visible non-temporal read
                    )
                    term = fx.arith.extf(f32_vec, value)
                    row_sum = term if row_sum is None else fx.arith.addf(row_sum, term)
                if const_expr(num_route_slots > 0):
                    row_sum = arith.select(has_absent_route, fx.arith.addf(row_sum, plus_zero), row_sum)
                buffer_store(fx.arith.trunc_f(bf16_vec, row_sum), output_res, token * fx.Int32(hidden) + col)
                vec_idx = vec_idx + fx.Int32(_WARP)
        if const_expr(has_grad_gate):
            # every valid route's dst has a primary route whose flag the first wave awaited above; lane j of
            # that wave moves route j's gate gradient, so the routes take one round trip, not one each
            is_valid_route = expert_ids[0] >= fx.Int32(0)
            for j in range_constexpr(1, num_topk):
                is_valid_route = arith.select(
                    lane_id == fx.Int32(j), expert_ids[j] >= fx.Int32(0), is_valid_route
                )
            if lane_id < fx.Int32(num_topk):
                gate_value = buffer_load(
                    combine_gate_res,
                    route_base + lane_id,
                    vec_width=1,
                    dtype=fx.T.f32,
                    cache_modifier=CPOL_SYSTEM_STREAM,
                )
                gate_value = arith.select(is_valid_route, gate_value, fx.Float32(0.0))
                buffer_store(gate_value, grad_topk_weights_res, route_base + lane_id)
        token = token + fx.Int32(num_reduce_warps)
