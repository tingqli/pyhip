# SPDX-License-Identifier: MIT
# Copyright (C) 2024-2026, Advanced Micro Devices, Inc. All rights reserved.

"""gfx942 EP8 MoE mega kernel: dispatch, GateUp and Down (with the combine) in one launch.

See docs/megamoe_ep8_942/mega_moe_ep8_design.md. ep_prep (ep_moe_comm_gfx942.cpp) runs first and builds the plan.
Workgroups take task tickets from per-XCD queues (persistent: one workgroup per CU taking tickets until the queues
are empty). A workgroup takes a ticket only when it is running and its current task (if any) waits for nothing more,
and a task only waits for lower tickets of its queue or for data that sources push without waiting, so the grid
needs no co-residency. Each queue holds:
  [0, producers)  P2P-write this rank's routes in the order the destinations' queues need them (ep_prep), then add
                  each route to arrived[its sorted block] on its destination.
  then            units of NG GateUp tiles of block u and ND Down tiles of block u - lag: Down, and the combine
                  traffic its epilogue sends, runs under the GateUp of later blocks instead of after all of it.
GateUp(b) waits until arrived[b] reaches the routes block b receives, writes a2 and counts done[b];
Down(b) waits until done[b] == NG and adds its rows into the source ranks' out with BF16 atomics.
"""

import functools
import os

import flydsl.compiler as flyc
import flydsl.expr as fx
import torch
from flydsl._mlir import ir
from flydsl._mlir.dialects import llvm
from flydsl.expr import const_expr, range_constexpr, rocdl
from flydsl.expr.typing import T
from flydsl.expr.typing import Vector as Vec

from .helpers import atomic_add_i32, buffer_rsrc_at, fence, load_i32_atomic, run_compiled, spin_wait_ge
from .moe_down_a8w8_blockscale_gfx942_lds import down_task_emitter
from .moe_gateup_a8w8_blockscale_gfx942_lds import OOB_OFFSET, SORT_BLOCK_M, _load_i32, _rsrc_of, _uniform, gateup_task_emitter

# Must match ep_moe_comm_gfx942.cpp. ws: ... then arrived [blocks]; sched: tickets, expected [blocks], done [blocks].
NPES, E_LOCAL = 8, 32
ARRIVED = NPES * NPES * E_LOCAL + 3 * NPES
SCHED_EXPECTED = 16
ROW_BITS = 17
# Routes per producer wave between two signals.
CHUNK = 8
# sc0 nt sc1: written through to the destination, so a vmcnt wait covers visibility before the signal.
P2P_AUX = 19


@functools.cache
def compile_ep_mega(
    hidden_dim, inter_dim, topk, token_shift, producers=32, lag=2, gateup_layout="2x4_pf1", down_layout="4x2_pf1", xcd_queues=True,
    relaxed=True, persistent=True, queue_order="paired", tasks_per_wg=1, trace=False, combine="bf16",
):
    """xcd_queues: one task queue per XCD (producers split evenly), so the tiles of a block share that XCD's L2; a
    workgroup whose queue is empty takes tasks from the next queues. lag counts units (block groups) of one queue.
    queue_order: blocks of queue q are "interleaved" (b % 8 == q), "contiguous" (an eighth of the blocks), or
    "paired" (contiguous, block pairs' tasks alternating tile by tile so both read each B tile together).
    relaxed: GateUp writes a2 through to memory (sc1) and both waits invalidate only the L1, instead of an L2
    write-back per GateUp and scoped L2 invalidations per task. All data a task waits for is in local memory, whose L2
    lines are kept coherent by probes, and nothing reads it before it is written within a launch.
    persistent: workgroups loop over tickets (launch about one per CU) instead of running one task each, and take
    the next ticket during the current task's epilogue.
    combine: "bf16" adds every route into its source rank's out with BF16 atomics; "fp8" stores it as an FP8 row
    with 1x128 scales into the source rank's comb[token, slot] (pOutTable / pOutScaleTable), summed afterwards.
    trace: every task writes int32 trace[8 s: 8 s + 8] (s = queue * queue_cap + ticket) = (start, wait done, end) in
    100 MHz ticks (low 32 bits of s_memrealtime), XCC id << 24 | HW_ID bits [8, 16) | kind (1 producer, 2 GateUp,
    3 Down), the time its workgroup began taking the ticket and, for producers, when wave 0 finished its first three
    chunks; for GateUp and Down, the shader clocks (s_memtime) from wait done to the end, to the K loop's start and to
    its end instead (the effective clock under the power limit, and the prologue / K loop / epilogue split)."""
    H, I = hidden_dim, inter_dim
    gateup = gateup_task_emitter(
        I, H, topk, E_LOCAL, gateup_layout, fp8_out=True, a_scale_token_major=True, store_aux=16 if relaxed else 0
    )
    down = down_task_emitter(
        H, I, topk, E_LOCAL, down_layout, atomic=True, sorted_a2=True, remote_token_shift=token_shift,
        fp8_routes=combine == "fp8",
    )
    # Closures must hold the emitters themselves: FlyDSL's cache key only recurses into callable closure values.
    emit_gateup, emit_down, SharedTiles = gateup.emit, down.emit, gateup.SharedTiles
    NG, ND = gateup.n_tiles, down.n_tiles
    unit = NG + ND
    topk_shift = topk.bit_length() - 1
    assert 1 << topk_shift == topk and H % 1024 == 0 and H // 128 * 4 <= 16 * 64
    scale_lanes = H // 128 * 4 // 16
    queues = 8 if xcd_queues else 1
    assert producers % queues == 0
    queue_producers = producers // queues
    contiguous = queue_order != "interleaved"
    pair = 2 if queue_order == "paired" else 1
    assert queue_order in ("interleaved", "contiguous", "paired"), queue_order

    def queue_cap(num_blocks):
        """Trace slots per queue (matches trace_entries): its producers and up to one empty pair partner."""
        return queue_producers + unit * ((num_blocks + (queues - 1)) // queues + 1)

    @flyc.kernel(known_block_size=[512, 1, 1])
    def mega_kernel(
        pRecvA: fx.Pointer,
        pW1: fx.Pointer,
        pA2: fx.Pointer,
        pA2Scale: fx.Pointer,
        pRecvScale: fx.Pointer,
        pW1Scale: fx.Pointer,
        pGuIds: fx.Pointer,
        pW2: fx.Pointer,
        pW2Scale: fx.Pointer,
        pDownIds: fx.Pointer,
        pRecvW: fx.Pointer,
        pOutTable: fx.Pointer,
        pOutScaleTable: fx.Pointer,
        pExpertIds: fx.Pointer,
        pNumValid: fx.Pointer,
        pSched: fx.Pointer,
        pWs: fx.Pointer,
        pX: fx.Pointer,
        pXScale: fx.Pointer,
        pTopkW: fx.Pointer,
        pSendRoute: fx.Pointer,
        pSendInfo: fx.Pointer,
        pPeerA: fx.Pointer,
        pPeerScale: fx.Pointer,
        pPeerIds: fx.Pointer,
        pPeerW: fx.Pointer,
        pPeerWs: fx.Pointer,
        pTrace: fx.Pointer,
        num_routes: fx.Int32,
        num_tokens: fx.Int32,
        me: fx.Int32,
        num_blocks: fx.Int32,
    ):
        tid = fx.thread_idx.x
        lane = tid % 64
        wave = _uniform(tid // 64)
        zero = fx.Int32(0).ir_value()
        aux = ir.IntegerAttr.get(T.i32, P2P_AUX)
        lds = fx.SharedAllocator().allocate(SharedTiles).peek()
        sched = fx.Int64(fx.ptrtoint(pSched))
        rows_cap = num_blocks * SORT_BLOCK_M

        def clock():
            if const_expr(not trace):
                return fx.Int32(0)
            ticks = llvm.inline_asm(T.i32, [], "s_memrealtime s[0:1]\ns_waitcnt lgkmcnt(0)\ns_mov_b32 $0, s0", "=s,~{s0},~{s1}", has_side_effects=True)
            return fx.Int32(ticks)

        def cycles():
            """Low word of the shader-clock counter (s_memtime), which runs at the current core clock."""
            if const_expr(not trace):
                return fx.Int32(0)
            ticks = llvm.inline_asm(T.i32, [], "s_memtime s[0:1]\ns_waitcnt lgkmcnt(0)\ns_mov_b32 $0, s0", "=s,~{s0},~{s1}", has_side_effects=True)
            return fx.Int32(ticks)

        def hwreg(name):
            return fx.Int32(llvm.inline_asm(T.i32, [], f"s_getreg_b32 $0, hwreg({name})", "=s", has_side_effects=True))

        def ticket_slot(index):
            return fx.make_view(lds.ab.ptr + index, fx.make_layout(1, 1))

        valid_rows = _uniform(_load_i32(_rsrc_of(pNumValid, 4), 0))
        blocks = (valid_rows + (SORT_BLOCK_M - 1)) // SORT_BLOCK_M
        blocks = (blocks < num_blocks).select(blocks, num_blocks)

        def queue_layout(queue):
            """(first block, block stride, blocks) of a queue."""
            if const_expr(contiguous):
                first = blocks * queue // queues
                return first, 1, blocks * (queue + 1) // queues - first
            return queue, queues, (blocks - queue + (queues - 1)) // queues

        def queue_tasks(queue):
            return queue_producers + unit * pair * ((queue_layout(queue)[2] + (pair - 1)) // pair)

        def lane0_add(addr, value):
            """Atomic add by lane 0 only; the old value in lane 0. The address goes through an opaque VGPR zero: at a
            uniform address LLVM's atomic optimizer sums the lanes in a 64-step loop and reads the result back at
            once (to broadcast it), so a prefetched ticket could not be left in flight."""
            taken = fx.Int32(0)
            if lane == 0:
                lane_zero = fx.Int32(llvm.inline_asm(T.i32, [], "v_mov_b32 $0, 0", "=v", has_side_effects=True))
                taken = atomic_add_i32(fx.Int64(addr) + fx.Int64(lane_zero), value)
            return taken

        def take_ticket(after_task=False, prefetched=None):
            """(queue, ticket, entry time) of this workgroup's next task; ticket -1 when every queue is empty.

            prefetched: wave 0's ticket of the home queue taken during the previous task (possibly past its end).
            """
            entry = clock()
            if const_expr(after_task):
                # The previous task's last LDS reads are done before the slots are overwritten.
                rocdl.s_barrier()
            # Wave-uniform branches only around barriers (a lane-divergent one lets LLVM move the barrier).
            if wave == 0:
                # This XCD's queue first (its blocks then share the XCD's L2), the others once it is empty. Plain
                # loads find the queues that may still hold tasks: once all are handed out, the leftover workgroups
                # of the (over-sized) grid exit after one round of loads instead of contending atomics (an atomic
                # per leftover workgroup, even on the home queue only, slows the tasks still running).
                home = hwreg("HW_REG_XCC_ID") & (queues - 1)
                cand = home
                got = fx.Int32(-1)
                if const_expr(prefetched is not None):
                    early = _uniform(prefetched)
                    got = (early < queue_tasks(home)).select(early, fx.Int32(-1))
                if got < 0:
                    open_mask = fx.Int32(0)
                    for q in range_constexpr(queues):
                        seen = _uniform(load_i32_atomic(sched + fx.Int64(q * 4), "agent-one-as"))
                        open_mask = open_mask | (seen < queue_tasks(fx.Int32(q))).select(fx.Int32(1 << q), fx.Int32(0))
                    tries = fx.Int32(0)
                    while (got < 0) & (tries < queues):
                        cand = (home + tries) & (queues - 1)
                        if ((open_mask >> cand) & 1) != 0:
                            taken = _uniform(lane0_add(sched + fx.Int64(cand * 4), 1))
                            got = (taken < queue_tasks(cand)).select(taken, fx.Int32(-1))
                        tries = tries + 1
                ticket_slot(0).store(Vec.from_elements([cand], fx.Int32))
                ticket_slot(1).store(Vec.from_elements([got], fx.Int32))
            rocdl.s_waitcnt(lgkmcnt=0)
            rocdl.s_barrier()
            queue = _uniform(Vec(ticket_slot(0).load())[0])
            ticket = _uniform(Vec(ticket_slot(1).load())[0])
            rocdl.s_waitcnt(lgkmcnt=0)
            rocdl.s_barrier()
            return queue, ticket, entry

        def record(queue, ticket, entry, started, waited, kind, run_cycles=None, loop_cycles=()):
            if const_expr(trace):
                ended = clock()
                where = (hwreg("HW_REG_XCC_ID") << 24) | (hwreg("HW_REG_HW_ID") & 0xFF00) | kind
                if wave == 0:
                    rsrc = _rsrc_of(pTrace, queues * queue_cap(num_blocks) * 32)
                    offset = (lane == 0).select((queue * queue_cap(num_blocks) + ticket) * 32, fx.Int32(OOB_OFFSET))
                    tail = entry if run_cycles is None else Vec.from_elements([entry, run_cycles, *loop_cycles], fx.Int32)
                    for part, words in enumerate([Vec.from_elements([started, waited, ended, where], fx.Int32), tail]):
                        rocdl.raw_ptr_buffer_store(
                            words.ir_value(), rsrc, (offset + part * 16).ir_value(), zero,
                            aux=ir.IntegerAttr.get(T.i32, 0),
                        )

        def produce(index, trace_slot):
            x_rsrc = _rsrc_of(pX, num_tokens * H)
            xs_rsrc = _rsrc_of(pXScale, num_tokens * (scale_lanes * 16))
            w_rsrc = _rsrc_of(pTopkW, num_routes * 4)
            route_rsrc = _rsrc_of(pSendRoute, num_routes * 4)
            info_rsrc = _rsrc_of(pSendInfo, num_routes * 4)
            oob = fx.Int32(OOB_OFFSET)
            scale_lane = lane < scale_lanes
            # Lane r < NPES holds the (lo, hi) halves of rank r's buffer bases.
            peer_lane = (lane & (NPES - 1)) * 8
            bases = []
            for table in (pPeerA, pPeerScale, pPeerIds, pPeerW, pPeerWs):
                table_rsrc = _rsrc_of(table, NPES * 8)
                bases.append((_load_i32(table_rsrc, peer_lane), _load_i32(table_rsrc, peer_lane + 4)))

            def peer_rsrc(which, rank, num_bytes):
                lo, hi = [fx.Uint32(rocdl.readlane(T.i32, half.ir_value(), rank.ir_value())) for half in bases[which]]
                return buffer_rsrc_at((fx.Uint64(hi) << 32) | fx.Uint64(lo), num_bytes)

            def lane_value(values, j):
                return fx.Int32(rocdl.readlane(T.i32, values.ir_value(), fx.Int32(j).ir_value()))

            # Wave j of the producers sends the routes ep_plan sorted into slice j, in order. (Sending faster, the
            # previous chunk's stores retiring under this chunk's loads, was measured slower overall: the GateUp
            # tasks of the first blocks then run against more memory and power contention.)
            per_slice = (num_routes + (producers * 8 - 1)) // (producers * 8)
            start = (index * 8 + wave) * per_slice
            stop = (start + per_slice < num_routes).select(start + per_slice, num_routes)
            done = fx.Int32(0)
            next_route = start
            while next_route < stop:
                position = next_route + lane
                mine = (lane < CHUNK) & (position < stop)
                offset = mine.select(position * 4, oob)
                routes = _load_i32(route_rsrc, offset)
                infos = _load_i32(info_rsrc, offset)
                send = mine & (infos >= 0)
                sends = send.select(fx.Int32(1), fx.Int32(0))
                # All loads of the chunk before any store: a store may alias a later load for all LLVM knows.
                pending = []
                for j in range_constexpr(CHUNK):
                    route = lane_value(routes, j)
                    ok = lane_value(sends, j) != 0
                    token = route >> topk_shift
                    data = [
                        rocdl.raw_ptr_buffer_load(
                            T.i32x4, x_rsrc, ok.select(lane * 16 + part * 1024 + token * H, oob).ir_value(), zero, zero
                        )
                        for part in range_constexpr(H // 1024)
                    ]
                    scales = rocdl.raw_ptr_buffer_load(
                        T.i32x4, xs_rsrc, (ok & scale_lane).select(lane * 16 + token * (scale_lanes * 16), oob).ir_value(), zero, zero
                    )
                    weight = _load_i32(w_rsrc, ok.select(route * 4, oob))
                    pending.append((route, lane_value(infos, j), ok, token, data, scales, weight))
                for route, info, ok, token, data, scales, weight in pending:
                    row = info & ((1 << ROW_BITS) - 1)
                    dest = ok.select(info >> (ROW_BITS + 5), fx.Int32(0))
                    a_dst = peer_rsrc(0, dest, rows_cap * H)
                    for part in range_constexpr(H // 1024):
                        rocdl.raw_ptr_buffer_store(
                            data[part], a_dst, ok.select(lane * 16 + part * 1024 + row * H, oob).ir_value(), zero, aux=aux
                        )
                    rocdl.raw_ptr_buffer_store(
                        scales, peer_rsrc(1, dest, rows_cap * (scale_lanes * 16)),
                        (ok & scale_lane).select(lane * 16 + row * (scale_lanes * 16), oob).ir_value(), zero, aux=aux,
                    )
                    row_off = (ok & (lane == 0)).select(row * 4, oob).ir_value()
                    down_id = (me << token_shift | token) | ((route & (topk - 1)) << 24)
                    rocdl.raw_ptr_buffer_store(down_id.ir_value(), peer_rsrc(2, dest, rows_cap * 4), row_off, zero, aux=aux)
                    rocdl.raw_ptr_buffer_store(weight.ir_value(), peer_rsrc(3, dest, rows_cap * 4), row_off, zero, aux=aux)
                rocdl.s_waitcnt(vmcnt=0)
                expert = infos >> ROW_BITS
                source = ((expert >> 5) & (NPES - 1)) * 4
                ws_lo, ws_hi = [fx.Uint32(rocdl.ds_bpermute(T.i32, source.ir_value(), half.ir_value())) for half in bases[4]]
                block_of_row = (infos & ((1 << ROW_BITS) - 1)) // SORT_BLOCK_M
                arrived = fx.Int64((fx.Uint64(ws_hi) << 32) | fx.Uint64(ws_lo)) + fx.Int64((ARRIVED + block_of_row) * 4)
                if send:
                    atomic_add_i32(arrived, 1, "one-as")
                if const_expr(trace):
                    # Wave 0 of the producer: end of its first three chunks in trace words 5, 6, 7.
                    first = (wave == 0) & (lane == 0) & (done < 3)
                    rocdl.raw_ptr_buffer_store(
                        clock().ir_value(), _rsrc_of(pTrace, queues * queue_cap(num_blocks) * 32),
                        first.select((trace_slot + 5 + done) * 4, fx.Int32(OOB_OFFSET)).ir_value(), zero,
                        aux=ir.IntegerAttr.get(T.i32, 0),
                    )
                done = done + 1
                next_route = next_route + CHUNK

        def prefetch_hook():
            """Epilog hook taking the next ticket of the home queue while the epilogue runs: the task has no waits
            left, so holding a ticket cannot delay one it depends on. Returns (hook, holder of wave 0's ticket)."""
            holder = []
            if const_expr(not persistent):
                return None, holder

            def hook():
                queue_addr = sched + fx.Int64((hwreg("HW_REG_XCC_ID") & (queues - 1)) * 4)
                taken = fx.Int32(-1)
                if wave == 0:
                    # Read back only at the next take_ticket: the epilogue's own loads retire it on the way.
                    taken = lane0_add(queue_addr, 1)
                holder.append(taken)

            return hook, holder

        def loop_marks(hook):
            """Trace: (K-loop start hook, epilogue hook, marks); marks get wave 0's shader clocks at the K loop's start
            and end (trace words 6, 7, relative to the end of the wait)."""
            marks = []
            if const_expr(not trace):
                return None, hook, marks

            def start():
                marks.append(cycles())

            def end():
                marks.append(cycles())
                if const_expr(hook is not None):
                    hook()

            return start, end, marks

        def gateup_task(block, tile, expert, at):
            # Only this block's routes: about two sources' worth, not the whole expert.
            expected = _uniform(_load_i32(_rsrc_of(pSched, (SCHED_EXPECTED + 2 * num_blocks) * 4), (SCHED_EXPECTED + block) * 4))
            if wave == 0:
                spin_wait_ge(fx.Int64(fx.ptrtoint(pWs)) + fx.Int64((ARRIVED + block) * 4), expected, "one-as", relaxed)
            rocdl.s_barrier()
            waited = clock()
            began = cycles()
            hook, holder = prefetch_hook()
            loop_start, hook, marks = loop_marks(hook)
            emit_gateup(
                lds, pRecvA, pW1, pA2, pA2Scale, pRecvScale, pW1Scale, pGuIds, rows_cap, num_blocks, True,
                lambda: (block, tile, expert), tid=tid, epilog_hook=hook, kloop_hook=loop_start,
            )
            rocdl.s_waitcnt(vmcnt=0)
            rocdl.s_barrier()
            if wave == 0:
                if const_expr(not relaxed):
                    fence("release", "agent-one-as")
                lane0_add(sched + fx.Int64((SCHED_EXPECTED + num_blocks + block) * 4), 1)
            record(*at, waited, 2, cycles() - began, [mark - began for mark in marks])
            return holder[0] if holder else fx.Int32(-1)

        def down_task(block, tile, expert, at):
            if wave == 0:
                spin_wait_ge(sched + fx.Int64((SCHED_EXPECTED + num_blocks + block) * 4), NG, "agent-one-as", relaxed)
            rocdl.s_barrier()
            waited = clock()
            began = cycles()
            hook, holder = prefetch_hook()
            loop_start, hook, marks = loop_marks(hook)
            emit_down(
                lds, pA2, pW2, pOutTable, pA2Scale, pW2Scale, pDownIds, pRecvW, pOutTable, pOutTable, NPES << token_shift,
                num_blocks, True, lambda: (block, tile, expert), tid=tid, epilog_hook=hook, pOutScale=pOutScaleTable,
                kloop_hook=loop_start,
            )
            record(*at, waited, 3, cycles() - began, [mark - began for mark in marks])
            return holder[0] if holder else fx.Int32(-1)

        def run_task(queue, ticket, entry):
            """Runs a task; returns the ticket prefetched during it (wave 0; -1 if none)."""
            at = (queue, ticket, entry, clock())
            next_ticket = fx.Int32(-1)
            if ticket < queue_producers:
                produce(queue * queue_producers + ticket, (queue * queue_cap(num_blocks) + ticket) * 8)
                record(*at, at[3], 1)
            else:
                index = ticket - queue_producers
                first, stride, own = queue_layout(queue)
                # Groups of `pair` blocks; their GateUp (Down) tasks alternate between the blocks tile by tile, so
                # neighbouring blocks of one expert read each B tile at about the same time.
                groups = (own + (pair - 1)) // pair
                gate_tasks, down_tasks = pair * NG, pair * ND
                group_tasks = gate_tasks + down_tasks
                lead = (groups < lag).select(groups, fx.Int32(lag))
                # GateUp of the first `lead` groups; then units of GateUp(group u) and Down(group u - lead); then the
                # Down of the last `lead` groups.
                in_head = index < gate_tasks * lead
                mid = index - gate_tasks * lead
                unit_of = mid // group_tasks
                slot = mid - unit_of * group_tasks
                in_mid = mid < group_tasks * (groups - lead)
                tail = mid - group_tasks * (groups - lead)
                is_gateup = in_head | (in_mid & (slot < gate_tasks))
                group = in_head.select(
                    index // gate_tasks,
                    in_mid.select(lead + unit_of - (slot >= gate_tasks).select(lead, fx.Int32(0)), groups - lead + tail // down_tasks),
                )
                sub = in_head.select(index % gate_tasks, in_mid.select((slot < gate_tasks).select(slot, slot - gate_tasks), tail % down_tasks))
                local = group * pair + sub % pair
                tile = sub // pair
                block = first + local * stride
                # An odd last block leaves its pair partner's tasks empty.
                if local < own:
                    expert = _uniform(_load_i32(_rsrc_of(pExpertIds, num_blocks * 4), block * 4))
                    if is_gateup:
                        next_ticket = gateup_task(block, tile, expert, at)
                    else:
                        next_ticket = down_task(block, tile, expert, at)
            return next_ticket

        kernel_pointers = (
            pRecvA, pW1, pA2, pA2Scale, pRecvScale, pW1Scale, pGuIds, pW2, pW2Scale, pDownIds, pRecvW, pOutTable,
            pOutScaleTable, pExpertIds, pNumValid, pSched, pWs, pX, pXScale, pTopkW, pSendRoute, pSendInfo, pPeerA,
            pPeerScale, pPeerIds, pPeerW, pPeerWs, pTrace,
        )

        def reload_args():
            """Kernel arguments and thread id read again through values LLVM cannot see through."""
            ptr4 = ir.Type.parse("!llvm.ptr<4>")
            segment = llvm.call_intrinsic(ptr4, "llvm.amdgcn.kernarg.segment.ptr", [], [], [])
            base = fx.Int64(
                llvm.inline_asm(T.i64, [llvm.ptrtoint(T.i64, segment)], "s_mov_b64 $0, $1", "=s,s", has_side_effects=True)
            )

            def load(offset, ty, align):
                return llvm.LoadOp(ty, llvm.inttoptr(ptr4, (base + offset).ir_value()), alignment=align).result

            # Pointers are 8-byte kernel arguments, the i32 scalars follow them.
            values = [fx.inttoptr(p.type, fx.Int64(load(8 * i, T.i64, 8))) for i, p in enumerate(kernel_pointers)]
            values += [fx.Int32(load(8 * len(kernel_pointers) + 4 * j, T.i32, 4)) for j in range(4)]
            thread = fx.Int32(fx.thread_idx.x).ir_value()
            values.append(fx.Int32(llvm.inline_asm(T.i32, [thread], "v_mov_b32 $0, $1", "=v,v", has_side_effects=True)))
            return values

        def rebind(values):
            nonlocal pRecvA, pW1, pA2, pA2Scale, pRecvScale, pW1Scale, pGuIds, pW2, pW2Scale, pDownIds, pRecvW
            nonlocal pOutTable, pOutScaleTable, pExpertIds, pNumValid, pSched, pWs, pX, pXScale, pTopkW, pSendRoute
            nonlocal pSendInfo, pPeerA, pPeerScale, pPeerIds, pPeerW, pPeerWs, pTrace, num_routes, num_tokens, me
            nonlocal num_blocks, tid, lane, wave, sched, rows_cap
            (
                pRecvA, pW1, pA2, pA2Scale, pRecvScale, pW1Scale, pGuIds, pW2, pW2Scale, pDownIds, pRecvW, pOutTable,
                pOutScaleTable, pExpertIds, pNumValid, pSched, pWs, pX, pXScale, pTopkW, pSendRoute, pSendInfo, pPeerA,
                pPeerScale, pPeerIds, pPeerW, pPeerWs, pTrace, num_routes, num_tokens, me, num_blocks, tid,
            ) = values
            lane = tid % 64
            wave = _uniform(tid // 64)
            sched = fx.Int64(fx.ptrtoint(pSched))
            rows_cap = num_blocks * SORT_BLOCK_M

        queue, ticket, entry = take_ticket()
        if const_expr(persistent):
            # A workgroup takes its next ticket in the epilogue of its task, when that task waits for nothing
            # more: a task still only waits for tickets that running workgroups hold (or for producers, which
            # never wait), and the ticket's atomic latency hides under the epilogue.
            while ticket >= 0:
                # Every task re-reads the arguments: with loop-invariant ones LLVM hoists all task kinds'
                # address math out of the loop and runs out of registers.
                rebind(reload_args())
                next_ticket = run_task(queue, ticket, entry)
                queue, ticket, entry = take_ticket(True, next_ticket)
        else:
            # Up to tasks_per_wg tasks back to back, unrolled: a loop would let LLVM hoist every task kind's
            # invariants out of it and run out of registers.
            for i in range_constexpr(tasks_per_wg):
                if const_expr(i > 0):
                    queue, ticket, entry = take_ticket(True)
                if ticket >= 0:
                    run_task(queue, ticket, entry)

    @flyc.jit
    def launch(
        pRecvA: fx.Pointer,
        pW1: fx.Pointer,
        pA2: fx.Pointer,
        pA2Scale: fx.Pointer,
        pRecvScale: fx.Pointer,
        pW1Scale: fx.Pointer,
        pGuIds: fx.Pointer,
        pW2: fx.Pointer,
        pW2Scale: fx.Pointer,
        pDownIds: fx.Pointer,
        pRecvW: fx.Pointer,
        pOutTable: fx.Pointer,
        pOutScaleTable: fx.Pointer,
        pExpertIds: fx.Pointer,
        pNumValid: fx.Pointer,
        pSched: fx.Pointer,
        pWs: fx.Pointer,
        pX: fx.Pointer,
        pXScale: fx.Pointer,
        pTopkW: fx.Pointer,
        pSendRoute: fx.Pointer,
        pSendInfo: fx.Pointer,
        pPeerA: fx.Pointer,
        pPeerScale: fx.Pointer,
        pPeerIds: fx.Pointer,
        pPeerW: fx.Pointer,
        pPeerWs: fx.Pointer,
        pTrace: fx.Pointer,
        num_routes: fx.Int32,
        num_tokens: fx.Int32,
        me: fx.Int32,
        num_blocks: fx.Int32,
        num_workgroups: fx.Int32,
        stream: fx.Stream = fx.Stream(None),
    ):
        mega_kernel(
            pRecvA, pW1, pA2, pA2Scale, pRecvScale, pW1Scale, pGuIds, pW2, pW2Scale, pDownIds, pRecvW, pOutTable,
            pOutScaleTable, pExpertIds, pNumValid, pSched, pWs, pX, pXScale, pTopkW, pSendRoute, pSendInfo, pPeerA,
            pPeerScale, pPeerIds, pPeerW, pPeerWs, pTrace, num_routes, num_tokens, me, num_blocks,
            value_attrs={"llvm.passthrough": [["target-features", "-packed-fp32-ops"]]},
        ).launch(grid=(num_workgroups, 1, 1), block=(512, 1, 1), stream=stream)

    launch.compile_hints["target_features"] = "-packed-fp32-ops"
    return launch


def mega_grid(op, producers):
    """Workgroups covering every task (each queue may add one empty pair partner)."""
    return producers + (op.hidden // 256 + op.inter // 128) * (op.s_cap // SORT_BLOCK_M + 8)


def trace_entries(op, producers):
    """int32 entries of a trace buffer for compile_ep_mega(trace=True), any queue count."""
    return 8 * 8 * (producers // 8 + (op.hidden // 256 + op.inter // 128) * (-(-op.s_cap // SORT_BLOCK_M // 8) + 1))


def ep_mega(op, x_fp8, x_scale, topk_w, producers=32, lag=2, xcd_queues=True, relaxed=True, persistent=True,
            queue_order="paired", tasks_per_wg=1, trace=None):
    """Run the mega kernel for an EPMoEGfx942 `op` whose ep_prep ran for this call.

    trace: optional int32 tensor of trace_entries(op, producers) entries (see compile_ep_mega).
    """
    launch = compile_ep_mega(
        op.hidden, op.inter, op.topk, op.token_shift, producers, lag, xcd_queues=xcd_queues, relaxed=relaxed,
        persistent=persistent, queue_order=queue_order, tasks_per_wg=tasks_per_wg, trace=trace is not None,
        combine=op.combine,
    )
    grid = int(os.environ.get("MEGA_GRID", 0)) or -(-mega_grid(op, producers) // tasks_per_wg)
    if persistent:
        grid = min(grid, torch.cuda.get_device_properties(x_fp8.device).multi_processor_count)
    t = op.tables
    fp8 = op.combine == "fp8"
    ptr = lambda tensor: flyc.from_c_void_p(fx.Int32, tensor.data_ptr())
    run_compiled(
        launch,
        ptr(op.recv_a), ptr(op.w1), ptr(op.a2), ptr(op.a2_scale_t), ptr(op.recv_scale), ptr(op.w1_scale), ptr(op.gu_ids),
        ptr(op.w2), ptr(op.w2_scale), ptr(op.down_ids), ptr(op.recv_w), ptr(t["comb" if fp8 else "out"]),
        ptr(t["comb_scale" if fp8 else "out"]), ptr(op.expert_ids), ptr(op.num_valid), ptr(op.sched), ptr(op.ws),
        ptr(x_fp8), ptr(x_scale), ptr(topk_w), ptr(op.send_route), ptr(op.send_info),
        ptr(t["recv_a"]), ptr(t["recv_scale"]), ptr(t["down_ids"]), ptr(t["recv_w"]), ptr(t["ws"]),
        ptr(op.sched if trace is None else trace),
        x_fp8.shape[0] * op.topk, x_fp8.shape[0], op.rank, op.s_cap // SORT_BLOCK_M, grid,
        torch.cuda.current_stream(),
    )
