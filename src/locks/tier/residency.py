"""Residency -- exact-LRU hot-buffer residency for the selected pages.

Per (layer, kv-head) the tier keeps a bounded VRAM ``hot`` buffer of ``S`` page
slots. Each decode step, the pages Stage A selected are looked up in the
residency map: HITS already sit in ``hot``; MISSES are gathered (from the pinned
pool if flushed, else the staging pool) into victim slots chosen by exact LRU.
Stage B then reads V from ``hot`` (+ the staging/pinned fallback for the partial
tail). This is the P1 machinery of the prototype, rewritten around two written
invariants:

  I2 (hot == residency): ``hot[l,kv,slot]`` ALWAYS holds the V of
     ``slot2page[l,kv,slot]``. Structurally enforced by making the gather the
     SINGLE owner of the (hot[slot], page2slot, slot2page) transition: it writes
     the hot bytes and re-points both maps in the same operation, and it reads
     from the correct source (pinned if ``pool_valid`` else staged via ``vbo``).
     The prototype's bug #2 was a gather whose staged-source path filled hot
     with the wrong page's V; here there is exactly one gather code path and its
     source selection is explicit. ``assert_maps_inverse`` checks the
     content-independent structural half every debug step.

  I3 (no aliasing, residency side): ``page2slot`` and ``slot2page`` are mutual
     inverses -- at most one slot per page, one page per slot. (The staging
     free-set half of I3 lives in staging.py.)

SCAFFOLD STATUS. The persistent buffers + invariant asserts are real. The
per-step map/gather update is a CORRECT torch reference (host-synchronizing, not
graph-safe) marked TODO to port to the graph-safe Triton/CUDA kernels that
already exist in ``vllm/kernels/dram_tier.py`` (``_vt_miss_diff_kernel`` /
``_select_victims_kernel`` / ``_p2_gather_kernel``). Because the mem-v Stage-B
tiered V-load is the documented FOLLOW-UP, ``gather`` is not yet called on the
hot path; it is provided complete so the follow-up wires decode without
re-architecting. See tier/README.md.
"""
from __future__ import annotations

import contextlib
import os

import torch
import triton
import triton.language as tl

_I32_MAX = tl.constexpr(2147483647)

# INV (2026-07-19 late): route invalidate_written through the one-launch CUDA
# port in k5_cuda.py (see the comment at the call site).  Kill switch: 0.
_INV_CUDA = os.environ.get("LOCKS_INV_CUDA", "0") == "1"


@triton.jit
def _miss_diff_kernel(tab_ptr, cnt_ptr, bt_ptr, sl_ptr,
                      p2s_ptr, lru_ptr, clock_ptr, fcnt_ptr,
                      NB, S, MP, NKV, stride_btr, stride_tr, stride_cr,
                      mpage_ptr, mcnt_ptr,
                      PAGE: tl.constexpr, BLOCK: tl.constexpr):
    """Per (request, kv-head): classify each selected COMPLETE page as a hot HIT
    (page2slot>=0, touch its LRU so it cannot be evicted this step) or a MISS
    (compact its physical block into mpage). Partial-tail pages are neither (the
    decode reads them from staged v_pool). VARIABLE-count native: ``n`` is the
    per-unit page_cnt device value. Program (0,0) also zeroes the flat fetch
    counter (no appends happen before the victims launch -> race-free).
    Ports ``_vt_miss_diff_kernel``."""
    r = tl.program_id(0)
    kv = tl.program_id(1)
    if (r == 0) & (kv == 0):
        tl.store(fcnt_ptr, 0)
    n = tl.load(cnt_ptr + r * stride_cr + kv)
    sl = tl.load(sl_ptr + r)
    clk = tl.load(clock_ptr)
    n_miss = clk * 0
    for off in range(0, n, BLOCK):
        idx = off + tl.arange(0, BLOCK)
        valid = idx < n
        pt = tl.load(tab_ptr + r * stride_tr + kv * MP + idx, mask=valid,
                     other=0)
        blk = tl.load(bt_ptr + r * stride_btr + pt, mask=valid, other=0)
        complete = ((pt + 1) * PAGE) <= sl
        slot = tl.load(p2s_ptr + kv * NB + blk, mask=valid, other=-1)
        is_hit = valid & complete & (slot >= 0)
        is_miss = valid & complete & (slot < 0)
        m32 = is_miss.to(tl.int32)
        mpos = tl.cumsum(m32, axis=0) - m32
        tl.store(mpage_ptr + r * stride_tr + kv * MP + n_miss + mpos, blk,
                 mask=is_miss)
        tl.store(lru_ptr + kv * S + slot, clk, mask=is_hit)
        n_miss += tl.sum(m32, axis=0)
    tl.store(mcnt_ptr + r * stride_cr + kv, n_miss)


@triton.jit
def _select_victims_kernel(mpage_ptr, mcnt_ptr,
                           p2s_ptr, s2p_ptr, lru_ptr, clock_ptr,
                           victim_ptr, ovf_ptr,
                           flist_ptr, fcnt_ptr, FCAP,
                           n_req, NB, S, MP, stride_tr, stride_cr,
                           BLOCK_S: tl.constexpr):
    """Per kv-head, sequential over (request, miss): pick the exact-LRU victim
    slot (min lru_clock among slots NOT touched this step), evict its old page,
    install the miss page, dedup pages already resident (shared prefix). SINGLE
    owner of the (page2slot, slot2page) transition (I2/I3). Every INSTALLED
    miss is also appended (atomically) to the FLAT fetch list (kv, blk, slot)
    -- the fetch kernel then walks [0, fetch_cnt) with a small strided grid
    instead of the (n_req*MP, n_kv) mostly-idle grid (measured 26us of pure
    idle-wave overhead per layer-step at 128 misses). Dedup keeps the list
    unique, so the strided fetch is race-free. Ports
    ``_vt_select_victims_kernel``."""
    kv = tl.program_id(0)
    clk = tl.load(clock_ptr)
    for r in range(0, n_req):
        m = tl.load(mcnt_ptr + r * stride_cr + kv)
        for i in range(0, m):
            blk = tl.load(mpage_ptr + r * stride_tr + kv * MP + i)
            cur = tl.load(p2s_ptr + kv * NB + blk)
            if cur >= 0:
                tl.store(victim_ptr + r * stride_tr + kv * MP + i, -1)
            else:
                best_c = clk * 0 + _I32_MAX
                best_s = clk * 0 - 1
                for s0 in range(0, S, BLOCK_S):
                    offs = s0 + tl.arange(0, BLOCK_S)
                    ck = tl.load(lru_ptr + kv * S + offs, mask=offs < S,
                                 other=_I32_MAX)
                    ck = tl.where(ck >= clk, _I32_MAX, ck)
                    bc = tl.min(ck, axis=0)
                    bs = tl.argmin(ck, axis=0).to(tl.int32) + s0
                    take = bc < best_c
                    best_s = tl.where(take, bs, best_s)
                    best_c = tl.where(take, bc, best_c)
                if best_s < 0:
                    tl.store(ovf_ptr, 1)
                    tl.store(victim_ptr + r * stride_tr + kv * MP + i, -1)
                else:
                    old = tl.load(s2p_ptr + kv * S + best_s)
                    if old >= 0:
                        tl.store(p2s_ptr + kv * NB + old, -1)
                    tl.store(p2s_ptr + kv * NB + blk, best_s)
                    tl.store(s2p_ptr + kv * S + best_s, blk)
                    tl.store(lru_ptr + kv * S + best_s, clk)
                    tl.store(victim_ptr + r * stride_tr + kv * MP + i, best_s)
                    fi = tl.atomic_add(fcnt_ptr, 1)
                    if fi < FCAP:
                        tl.store(flist_ptr + fi * 3 + 0, kv)
                        tl.store(flist_ptr + fi * 3 + 1, blk)
                        tl.store(flist_ptr + fi * 3 + 2, best_s)


@triton.jit
def _step_setup_kernel(clock_ptr, fcnt_ptr):
    """TAIL-OPT per-layer-step setup, ONE tiny launch: advance the global LRU
    clock (replaces the host-side ``self.clock += 1`` torch launch) and zero
    the flat fetch counter (previously program (0,0) of miss_diff -- which
    would be RACY inside the fused plan kernel, where other programs append
    concurrently).  Runs BEFORE the plan kernel, so every program of the plan
    sees the advanced clock and a zeroed counter: bitwise-identical state
    machine to the unfused (add_ + miss_diff + victims) chain."""
    clk = tl.load(clock_ptr)
    tl.store(clock_ptr, clk + 1)
    tl.store(fcnt_ptr, 0)


@triton.jit
def _gather_kernel(pool_ptr, hot_ptr, vp_ptr, vbo_ptr, valid_ptr,
                   poolk_ptr, hotk_ptr, kp_ptr,
                   mpage_ptr, mcnt_ptr, victim_ptr,
                   lidx, NB, S, MP, NKV, stride_tr, stride_cr,
                   svb, svt, svh,
                   PAGE: tl.constexpr, D: tl.constexpr, HAS_K: tl.constexpr):
    """Bring each miss page's V (and K, mem-kv) into its victim ``hot`` slot:
    from the pinned pool if flushed (zero-copy int16 UVA read), else from the
    staged pool via vbo (+ lazy write-through to the pinned pool). K and V share
    the miss list + victim slot. SINGLE owner of the hot bytes; keeps hot ==
    residency (I2). Grid (n_req*MP, n_kv). Ports ``_p2_gather_kernel``."""
    j = tl.program_id(0)
    kv = tl.program_id(1)
    r = j // MP
    i = j % MP
    m = tl.load(mcnt_ptr + r * stride_cr + kv)
    if i < m:
        slot = tl.load(victim_ptr + r * stride_tr + kv * MP + i)
        if slot >= 0:
            blk = tl.load(mpage_ptr + r * stride_tr + kv * MP + i)
            vld = tl.load(valid_ptr + kv * NB + blk)
            offs_t = tl.arange(0, PAGE)
            offs_d = tl.arange(0, D)
            tile = offs_t[:, None] * D + offs_d[None, :]
            pool_off = (((lidx * NB + blk) * NKV + kv).to(tl.int64) * (PAGE * D))
            hot_off = ((kv * S + slot).to(tl.int64) * (PAGE * D))
            if vld > 0:
                tl.store(hot_ptr + hot_off + tile,
                         tl.load(pool_ptr + pool_off + tile))
                if HAS_K:
                    tl.store(hotk_ptr + hot_off + tile,
                             tl.load(poolk_ptr + pool_off + tile))
            else:
                vb = tl.load(vbo_ptr + blk)
                if vb >= 0:
                    stg = vb.to(tl.int64) * svb + kv * svh \
                        + offs_t[:, None] * svt + offs_d[None, :]
                    v16 = tl.load(vp_ptr + stg).to(tl.int16, bitcast=True)
                    tl.store(hot_ptr + hot_off + tile, v16)
                    tl.store(pool_ptr + pool_off + tile, v16)
                    if HAS_K:
                        k16 = tl.load(kp_ptr + stg).to(tl.int16, bitcast=True)
                        tl.store(hotk_ptr + hot_off + tile, k16)
                        tl.store(poolk_ptr + pool_off + tile, k16)
                    tl.store(valid_ptr + kv * NB + blk, tl.cast(1, tl.int8))
                else:
                    tl.store(hot_ptr + hot_off + tile,
                             tl.load(pool_ptr + pool_off + tile))
                    if HAS_K:
                        tl.store(hotk_ptr + hot_off + tile,
                                 tl.load(poolk_ptr + pool_off + tile))


@triton.jit
def _fetch_flat_kernel(pool_ptr, hot_ptr, vp_ptr, vbo_ptr, valid_ptr,
                       poolk_ptr, hotk_ptr, kp_ptr,
                       flist_ptr, fcnt_ptr,
                       lidx, NB, S, NKV, FCAP,
                       svb, svt, svh,
                       GRID: tl.constexpr, PAGE: tl.constexpr,
                       D: tl.constexpr, HAS_K: tl.constexpr):
    """Flat-list miss fetch: program p copies pages p, p+GRID, ... of the
    COMPACTED (kv, blk, slot) fetch list -- the grid is a small constant
    (GRID programs) instead of (n_req*MP, n_kv), so the idle-wave cost is ~1
    wave regardless of MP (the old grid measured 26us of PURE overhead per
    layer-step at 128 misses), and the per-page work is identical to
    ``_gather_kernel`` (pinned zero-copy if flushed, else staged with lazy
    write-through to the pinned pool). Load-balanced across the DYNAMIC b_u
    skew by construction (page-level striding, not unit-level)."""
    pid = tl.program_id(0)
    n = tl.minimum(tl.load(fcnt_ptr), FCAP)
    offs_t = tl.arange(0, PAGE)
    offs_d = tl.arange(0, D)
    tile = offs_t[:, None] * D + offs_d[None, :]
    for i in range(pid, n, GRID):
        kv = tl.load(flist_ptr + i * 3 + 0)
        blk = tl.load(flist_ptr + i * 3 + 1)
        slot = tl.load(flist_ptr + i * 3 + 2)
        vld = tl.load(valid_ptr + kv * NB + blk)
        pool_off = (((lidx * NB + blk) * NKV + kv).to(tl.int64) * (PAGE * D))
        hot_off = ((kv * S + slot).to(tl.int64) * (PAGE * D))
        if vld > 0:
            tl.store(hot_ptr + hot_off + tile,
                     tl.load(pool_ptr + pool_off + tile))
            if HAS_K:
                tl.store(hotk_ptr + hot_off + tile,
                         tl.load(poolk_ptr + pool_off + tile))
        else:
            vb = tl.load(vbo_ptr + blk)
            if vb >= 0:
                stg = vb.to(tl.int64) * svb + kv * svh \
                    + offs_t[:, None] * svt + offs_d[None, :]
                v16 = tl.load(vp_ptr + stg).to(tl.int16, bitcast=True)
                tl.store(hot_ptr + hot_off + tile, v16)
                tl.store(pool_ptr + pool_off + tile, v16)
                if HAS_K:
                    k16 = tl.load(kp_ptr + stg).to(tl.int16, bitcast=True)
                    tl.store(hotk_ptr + hot_off + tile, k16)
                    tl.store(poolk_ptr + pool_off + tile, k16)
                tl.store(valid_ptr + kv * NB + blk, tl.cast(1, tl.int8))
            else:
                tl.store(hot_ptr + hot_off + tile,
                         tl.load(pool_ptr + pool_off + tile))
                if HAS_K:
                    tl.store(hotk_ptr + hot_off + tile,
                             tl.load(poolk_ptr + pool_off + tile))


@triton.jit
def _invalidate_kernel(bt_ptr, sl_ptr, qsl_ptr,
                       p2s_ptr, s2p_ptr, valid_ptr, gen_ptr,
                       NB, S, stride_btr,
                       PAGE: tl.constexpr, NKV: tl.constexpr,
                       KV_PAD: tl.constexpr):
    """Drop pool_valid + hot residency for every page (re)written this step
    (block reuse / chunked prefill make both the hot copy AND the pinned copy
    stale). Grid (L, n_req), OUTSIDE the graph before flush/gather. Ports
    ``_vt_invalidate_kernel``.

    K5 additions: (a) a PENDING mapping (page2slot == -2, copy-engine transfer
    in flight) is reset to -1 like a resident one -- the in-flight bytes are
    stale; the promote abandons the entry via (b) the per-block GENERATION
    bump, which also guards the ABA case (same block PENDING again before the
    stale entry drains). Only program l==0 bumps gen (one bump per rewrite)."""
    l = tl.program_id(0)
    r = tl.program_id(1)
    sl = tl.load(sl_ptr + r)
    if sl > 0:
        ql = tl.load(qsl_ptr + r + 1) - tl.load(qsl_ptr + r)
        p0 = (sl - ql) // PAGE
        p1 = (sl - 1) // PAGE
        offs_kv = tl.arange(0, KV_PAD)
        kmask = offs_kv < NKV
        for p in range(p0, p1 + 1):
            blk = tl.load(bt_ptr + r * stride_btr + p)
            if l == 0:
                tl.atomic_add(gen_ptr + blk, 1)
            rows = (l * NKV + offs_kv) * NB + blk
            tl.store(valid_ptr + rows, tl.zeros([KV_PAD], tl.int8), mask=kmask)
            slot = tl.load(p2s_ptr + rows, mask=kmask, other=-1)
            res = kmask & (slot >= 0)
            gone = kmask & (slot != -1)          # resident OR pending
            tl.store(p2s_ptr + rows, tl.full([KV_PAD], -1, tl.int32),
                     mask=gone)
            tl.store(s2p_ptr + (l * NKV + offs_kv) * S + slot,
                     tl.full([KV_PAD], -1, tl.int32), mask=res)


class Residency:
    """Exact-LRU hot-buffer residency state (all layers, all kv-heads)."""

    def __init__(self, *, num_layers: int, num_blocks: int, n_kv: int,
                 hot_slots: int, page: int, d: int, max_reqs: int,
                 max_pages: int, dtype: torch.dtype, device,
                 offload_k: bool = False):
        self.L, self.NB, self.n_kv = num_layers, num_blocks, n_kv
        self.S, self.page, self.d = hot_slots, page, d
        self.R, self.MP = max_reqs, max_pages
        self.dtype = dtype
        self.offload_k = offload_k
        dev = torch.device(device)
        self.device = dev
        i32, i8 = torch.int32, torch.int8

        # ---- VRAM hot buffer: bounded by S (working set), NOT NB ---------- #
        # THE only KV bytes resident under mem-kv (besides the r8 summary): the
        # bounded hot cache of fetched pages. mem-kv adds a parallel K hot cache.
        self.hot = torch.zeros((num_layers, n_kv, hot_slots, page, d),
                               dtype=dtype, device=dev)
        self.hot_i16 = self.hot.view(torch.int16)   # bit-exact kernel view
        self.hot_k = (torch.zeros((num_layers, n_kv, hot_slots, page, d),
                                  dtype=dtype, device=dev) if offload_k else None)
        self.hot_k_i16 = self.hot_k.view(torch.int16) if offload_k else None

        # ---- residency maps (NB-sized VRAM bookkeeping; int8/int32) ------- #
        # page2slot[l,kv,blk] = hot slot holding this physical block, or -1.
        self.page2slot = torch.full((num_layers, n_kv, num_blocks), -1,
                                    dtype=i32, device=dev)
        # slot2page[l,kv,slot] = physical block resident in this slot, or -1.
        self.slot2page = torch.full((num_layers, n_kv, hot_slots), -1,
                                    dtype=i32, device=dev)
        # exact-LRU clock per slot; a slot touched/claimed this step == clock.
        self.lru_clock = torch.zeros((num_layers, n_kv, hot_slots),
                                     dtype=i32, device=dev)
        # pool_valid[l,kv,blk] = 1 once this block's V is flushed to the pinned
        # pool (a zero-copy read is then legal). Owned jointly with staging.
        self.pool_valid = torch.zeros((num_layers, n_kv, num_blocks),
                                      dtype=i8, device=dev)
        # per-block rewrite generation (K5 promote ABA guard; bumped by
        # invalidate_written once per rewritten block).
        self.gen = torch.zeros((num_blocks,), dtype=i32, device=dev)
        # K5 claim word per slot (0 free / unit tag; held while a copy-engine
        # transfer is in flight) + CLOCK hand per (l, kv).
        self.owner = torch.zeros((num_layers, n_kv, hot_slots), dtype=i32,
                                 device=dev)
        self.hand = torch.zeros((num_layers, n_kv), dtype=i32, device=dev)
        self.clock = torch.ones((1,), dtype=i32, device=dev)
        self.overflow = torch.zeros((1,), dtype=i32, device=dev)

        # ---- per-step gather scratch (request-row keyed) ------------------ #
        self.miss_pages = torch.zeros((max_reqs, n_kv, max_pages),
                                      dtype=i32, device=dev)
        self.miss_cnt = torch.zeros((max_reqs, n_kv), dtype=i32, device=dev)
        self.victim_slots = torch.zeros((max_reqs, n_kv, max_pages),
                                        dtype=i32, device=dev)
        # ---- flat fetch list: (kv, blk, slot) per INSTALLED miss ---------- #
        # Sized to the dedup-free worst case (every unit misses every selected
        # page) so the append guard NEVER truncates -- a truncated append
        # would install a residency mapping without its bytes (I2 violation).
        # The fetch kernel walks [0, fetch_cnt) with a small strided grid
        # (fetch_grid programs), decoupling launch overhead from max_pages.
        self.FCAP = max_reqs * n_kv * max_pages
        self.fetch_list = torch.zeros((self.FCAP, 3), dtype=i32, device=dev)
        self.fetch_cnt = torch.zeros((1,), dtype=i32, device=dev)
        self.fetch_grid = 1024

        elem = torch.empty(0, dtype=dtype).element_size()
        hot_n = self.hot.numel() + (self.hot_k.numel() if offload_k else 0)
        self.hot_gib = hot_n * elem / 2**30
        self.maps_gib = sum(t.numel() * t.element_size() for t in (
            self.page2slot, self.slot2page, self.lru_clock, self.pool_valid,
            self.miss_pages, self.miss_cnt, self.victim_slots,
            self.fetch_list, self.fetch_cnt)) / 2**30

    # --------------------------------------------------------------------- #
    # Per-step lifecycle (outside the graph unless noted)                   #
    # --------------------------------------------------------------------- #
    def invalidate_written(self, block_table, seq_lens, query_start_loc) -> None:
        """Drop residency + pool validity for every page (re)written this step
        (block reuse / chunked prefill make the hot copy AND the pinned copy
        stale). Runs before flush/gather so a rewritten page re-stages.

        SCAFFOLD: torch reference. TODO port ``_vt_invalidate_kernel``
        (graph-safe, no host sync). Keyed by physical block so it clears both
        maps and ``pool_valid`` for the affected blocks across all layers/heads.
        """
        # INV (2026-07-19 late): the Triton walker costs 24.9us/step EXPOSED
        # on the main stream (graphprof nsys_gt_tg) for O(1) real work at
        # bs=1; the CUDA port is one launch, one CTA/request, one thread per
        # (l, kv) row, VERBATIM store semantics (k5_cuda.py::inv_written).
        # Kill switch LOCKS_INV_CUDA=0 -> this Triton reference.
        if _INV_CUDA and self.L * self.n_kv <= 1024:
            from . import k5_cuda
            mod = k5_cuda.get_mod()
            if mod is not None:
                mod.inv_written(block_table, seq_lens, query_start_loc,
                                self.page2slot, self.slot2page,
                                self.pool_valid, self.gen,
                                self.NB, self.S, self.page,
                                self.L, self.n_kv)
                return
        n_req = seq_lens.shape[0]
        kv_pad = max(1, triton.next_power_of_2(self.n_kv))
        _invalidate_kernel[(self.L, n_req)](
            block_table, seq_lens, query_start_loc,
            self.page2slot, self.slot2page, self.pool_valid, self.gen,
            self.NB, self.S, block_table.stride(0),
            PAGE=self.page, NKV=self.n_kv, KV_PAD=kv_pad, num_warps=1)

    def gather(self, layer, page_table, page_cnt, block_table, seq_lens,
               n_req, staging, pool, poolk=None) -> None:
        """Bring every selected MISS page into ``hot`` (I2), choosing victim
        slots by exact LRU (I3). Source: pinned pool if ``pool_valid`` else the
        staging ``v_pool`` via ``vbo`` (with lazy write-through to the pinned
        pool). SINGLE owner of the (hot, page2slot, slot2page) transition.

        Graph-safe (fixed grids, no host sync). ``pool`` is the MappedHostVPool
        device view (int16). Fuses miss_diff + select_victims + gather; the LRU
        clock advances once per call so the previous step's touches become
        evictable. Ports _vt_miss_diff/_select_victims/_p2_gather (dram_tier.py).
        """
        self.gather_plan(layer, page_table, page_cnt, block_table, seq_lens,
                         n_req)
        self.gather_fetch(layer, staging, pool, n_req, poolk=poolk)

    def gather_plan(self, layer, page_table, page_cnt, block_table, seq_lens,
                    n_req) -> None:
        """miss_diff + select_victims: decide which selected pages MISS the hot
        buffer and which victim slot each takes (updates page2slot/slot2page/LRU
        and writes miss_cnt/victim_slots). No V movement -> cheap; the fetch is
        gather_fetch. Split out so (a) the residency HIT RATE = 1 - miss_cnt/sel
        is measurable and (b) the PCIe fetch can be overlapped with compute."""
        l = layer
        n_kv, S, NB, MP = self.n_kv, self.S, self.NB, self.MP
        self.clock += 1
        _miss_diff_kernel[(n_req, n_kv)](
            page_table, page_cnt, block_table, seq_lens,
            self.page2slot[l], self.lru_clock[l], self.clock, self.fetch_cnt,
            NB, S, MP, n_kv, block_table.stride(0), page_table.stride(0),
            page_cnt.stride(0), self.miss_pages, self.miss_cnt,
            PAGE=self.page, BLOCK=256, num_warps=4)
        _select_victims_kernel[(n_kv,)](
            self.miss_pages, self.miss_cnt,
            self.page2slot[l], self.slot2page[l], self.lru_clock[l], self.clock,
            self.victim_slots, self.overflow,
            self.fetch_list, self.fetch_cnt, self.FCAP,
            n_req, NB, S, MP, self.miss_pages.stride(0),
            self.miss_cnt.stride(0), BLOCK_S=1024, num_warps=4)

    def gather_fetch(self, layer, staging, pool, n_req, stream=None,
                     poolk=None) -> None:
        """Fetch the planned MISS pages' V (and K, mem-kv) into their hot victim
        slots (pinned zero-copy or staged write-through). The ONLY PCIe-touching
        step; runs on ``stream`` if given (async prefetch / double-buffer).
        Walks the FLAT (kv, blk, slot) list ``gather_plan`` compacted with a
        small strided grid: the launch cost no longer scales with
        n_req*max_pages (26us of idle-grid overhead at 16K ctx measured on the
        old (n_req*MP, n_kv) grid) and the work is page-level load-balanced
        regardless of the dynamic per-unit b_u skew."""
        l = layer
        n_kv, S, NB = self.n_kv, self.S, self.NB
        vp = staging.v_pool[l]                     # (NV, page, n_kv, d) bf16
        has_k = self.hot_k_i16 is not None
        kp = staging.k_pool[l] if has_k else vp
        hotk = self.hot_k_i16[l] if has_k else self.hot_i16[l]
        pk = poolk if has_k else pool
        ctx = torch.cuda.stream(stream) if stream is not None \
            else contextlib.nullcontext()
        with ctx:
            _fetch_flat_kernel[(self.fetch_grid,)](
                pool, self.hot_i16[l], vp, staging.vbo, self.pool_valid[l],
                pk, hotk, kp,
                self.fetch_list, self.fetch_cnt,
                l, NB, S, n_kv, self.FCAP,
                vp.stride(0), vp.stride(1), vp.stride(2),
                GRID=self.fetch_grid, PAGE=self.page, D=self.d, HAS_K=has_k,
                num_warps=4)

    def build_dma_plan(self, layer, pool, n_req, poolk=None):
        """Build the copy-engine descriptor list for the FLUSHED (pinned) miss
        pages: coalesce contiguous physical-block RUNS per kv-head into strided
        2-D copies (``dst`` = hot slots at ``page*d`` stride, ``src`` = pinned
        pool at ``n_kv*page*d`` block stride). Returns (runs, has_staged) where
        ``runs`` is a list of (dst, src, dpitch, spitch, width_bytes, height,
        dstk, srck) tuples. This is the HOST-side, D2H-syncing, python-loop part
        -- for a PREFETCH it runs during the PREVIOUS step's compute so its cost
        is hidden; ``issue_dma_plan`` is the cheap per-step copy issue.

        Bit-exact: pure int16 byte copy (pool + hot are the int16 view), identical
        bits to the UVA kernel; only the transport (copy engine vs SM) differs.
        """
        l = layer
        n_kv, S, NB = self.n_kv, self.S, self.NB
        page, d = self.page, self.d
        pbytes = page * d * 2
        blk_stride_b = n_kv * page * d * 2
        slot_stride_b = page * d * 2
        has_k = self.hot_k_i16 is not None
        mcnt = self.miss_cnt.to("cpu")
        mpage = self.miss_pages.to("cpu")
        vict = self.victim_slots.to("cpu")
        valid = self.pool_valid[l].to("cpu")
        pool_base = pool.data_ptr()
        hot_base = self.hot_i16[l].data_ptr()
        poolk_base = poolk.data_ptr() if (has_k and poolk is not None) else None
        hotk_base = self.hot_k_i16[l].data_ptr() if has_k else None
        pool_l_off = ((l * NB) * n_kv) * page * d * 2
        runs = []
        has_staged = False
        for r in range(n_req):
            for kv in range(n_kv):
                m = int(mcnt[r, kv])
                i = 0
                while i < m:
                    slot = int(vict[r, kv, i]); blk = int(mpage[r, kv, i])
                    if slot < 0:
                        i += 1; continue
                    if int(valid[kv, blk]) == 0:
                        has_staged = True; i += 1; continue
                    run = 1
                    while (i + run < m and int(vict[r, kv, i + run]) == slot + run
                           and int(mpage[r, kv, i + run]) == blk + run
                           and int(valid[kv, blk + run]) == 1):
                        run += 1
                    src = pool_base + pool_l_off + (blk * n_kv + kv) * pbytes
                    dst = hot_base + (kv * S + slot) * pbytes
                    dstk = (hotk_base + (kv * S + slot) * pbytes) if has_k else 0
                    srck = (poolk_base + pool_l_off + (blk * n_kv + kv) * pbytes) \
                        if has_k else 0
                    runs.append((dst, src, slot_stride_b, blk_stride_b, pbytes,
                                 run, dstk, srck))
                    i += run
        return runs, has_staged

    def issue_dma_plan(self, runs, copy_engine, stream) -> None:
        """Issue a prebuilt DMA plan on ``stream`` (pure copy-engine; no D2H, no
        python-per-miss beyond iterating the coalesced runs). This is the part
        that overlaps decode."""
        has_k = self.hot_k_i16 is not None
        for dst, src, dpitch, spitch, wbytes, height, dstk, srck in runs:
            if height == 1:
                copy_engine.memcpy_async(dst, src, wbytes, stream)
                if has_k:
                    copy_engine.memcpy_async(dstk, srck, wbytes, stream)
            else:
                copy_engine.memcpy_2d_async(dst, dpitch, src, spitch, wbytes,
                                            height, stream)
                if has_k:
                    copy_engine.memcpy_2d_async(dstk, dpitch, srck, spitch,
                                                wbytes, height, stream)

    def gather_fetch_dma(self, layer, staging, pool, n_req, copy_engine,
                         poolk=None, stream=None) -> "torch.cuda.Event":
        """Copy-engine miss fetch (per-step convenience = build + issue). The
        FLUSHED pages go through the copy engine; STAGED (unflushed) pages stay on
        the device-to-device kernel. Returns the side-stream event. NOTE the
        host-side ``build_dma_plan`` dominates per-step; the amortised path is
        prefetch (build during step N-1, ``issue_dma_plan`` in step N)."""
        stream = stream if stream is not None else copy_engine.next_stream()
        runs, has_staged = self.build_dma_plan(layer, pool, n_req, poolk=poolk)
        with torch.cuda.stream(stream):
            self.issue_dma_plan(runs, copy_engine, stream)
        ev = torch.cuda.Event(); ev.record(stream)
        if has_staged:
            self._gather_staged_only(layer, staging, pool, n_req, poolk)
        return ev

    def _gather_staged_only(self, layer, staging, pool, n_req, poolk=None):
        """Fallback for STAGED (unflushed) miss pages: the existing gather kernel
        (device-to-device from v_pool, no PCIe). Flushed pages it re-copies are a
        harmless idempotent overwrite (same bytes); to avoid that we could mask,
        but the staged set is tiny (only the last ~chunk of un-flushed pages)."""
        n_kv, S, NB, MP = self.n_kv, self.S, self.NB, self.MP
        vp = staging.v_pool[layer]
        has_k = self.hot_k_i16 is not None
        kp = staging.k_pool[layer] if has_k else vp
        hotk = self.hot_k_i16[layer] if has_k else self.hot_i16[layer]
        pk = poolk if has_k else pool
        _gather_kernel[(n_req * MP, n_kv)](
            pool, self.hot_i16[layer], vp, staging.vbo, self.pool_valid[layer],
            pk, hotk, kp,
            self.miss_pages, self.miss_cnt, self.victim_slots,
            layer, NB, S, MP, n_kv, self.miss_pages.stride(0),
            self.miss_cnt.stride(0),
            vp.stride(0), vp.stride(1), vp.stride(2),
            PAGE=self.page, D=self.d, HAS_K=has_k, num_warps=4)

    # --------------------------------------------------------------------- #
    # Invariant checks (call in debug; cheap, content-independent)          #
    # --------------------------------------------------------------------- #
    def assert_maps_inverse(self, layer: int | None = None,
                            pending_evict: dict | None = None,
                            pending_incoming: list | None = None) -> None:
        """I2/I3 (residency, structural half): the addressing relation between
        ``page2slot`` (page -> slot, or -1 absent / -2 PENDING) and
        ``slot2page`` (slot -> page, or -1 empty), checked WITHOUT touching V.

        OBSERVATION POINT: a host-synchronized instant between steps (the tier
        prologue ``begin_step``, or the end of a driven step in the kernel
        gates).  Nothing in-graph may be mid-flight on the main stream.

        THE INVARIANT, per (layer, kv-head).  Write ``P = slot2page[h]``,
        ``own = owner[h]`` (0 free, non-zero = a transfer targeting ``h`` is
        claimed), and let ``E`` be the PENDING-EVICT set: the ``(l, kv, blk, h)``
        claim records whose GRAPH-HEAD evict (``_k5_evict_kernel``) has not run
        yet -- ``k5.elist_dev[:ecnt]`` (published by this prologue, applied at
        the graph head) plus ``k5.mail[:mail_cnt]`` (claims not yet snapshotted).
        ``E`` is EMPTY under the legacy in-stream-claim schedule (``Tier.step``),
        where k5b re-points ``slot2page`` at claim time; it is non-empty only
        under the PLAN / deferred-evict schedule (``Tier.side_step``), where the
        claim marks k5-private state ONLY (owner, epoch, mailbox) and the image
        mutation is deferred to the next graph head.

          R1  settled inverse.      own == 0 and P >= 0  =>  page2slot[P] == h.
          R2  settled injectivity.  the pages held by owner-free slots are
                                    distinct (no two slots hold one page).
          R3  advertised back-ref.  page2slot[b] = h >= 0  =>  slot2page[h] == b.
                                    (A page may never be advertised at a slot
                                    that does not record it -- this is the
                                    direction that catches the mns>1 wrong-V
                                    signature, where a slot's BYTES belong to a
                                    different page than page2slot claims: the
                                    bytes follow slot2page, the reader follows
                                    page2slot, so any disagreement is exactly a
                                    wrong-V read.)
          R4  claimed slot.         own != 0 and P >= 0  =>  EITHER
                                    page2slot[P] < 0   (INCOMING: P is the page
                                      being brought in, still PENDING (-2) or
                                      invalidated (-1); the slot was already
                                      re-pointed -- legacy claim, or PLAN after
                                      the graph-head evict), OR
                                    page2slot[P] == h AND (l, kv, ., h) in E
                                      (OUTGOING: P is the page still legitimately
                                      resident in h -- its bytes are still the
                                      ones in the slot -- and the eviction that
                                      un-advertises it is QUEUED for the graph
                                      head, which runs before any decode of the
                                      next step reads page2slot).
                                    Anything else -- above all page2slot[P] = h'
                                    >= 0 with h' != h -- is corruption.
          R5  incoming exclusivity. for every (l, kv, blk, h) in E:
                                    page2slot[blk] < 0.  The page whose bytes are
                                    being transported into ``h`` is NEVER
                                    simultaneously advertised as resident.  This
                                    is the old in-flight assertion, relocated:
                                    under PLAN the incoming page is recorded in
                                    the claim record, not yet in slot2page[h].

        TRANSIENTS ALLOWED, and only these: the R4 OUTGOING arm, gated on a
        queued evict for that exact slot.  With ``pending_evict=None`` (the
        default, and every legacy caller) ``E`` is empty and R4 degenerates to
        the historical rule ``page2slot[slot2page[h]] < 0`` -- so this checker is
        STRICTLY STRONGER than its predecessor everywhere except that one gated
        arm, and adds R3 + R5, which the predecessor did not check at all.

        K7 REFINEMENT (sec 22c change 3; NARROWS, never weakens):
          * ``pending_evict`` values are ``(blk, gen)`` and contain ONLY rows
            with an ASSIGNED slot (h >= 0).  Under K7, raw-mail rows carry no
            slot and hold no claim -- they must not enable the R4 exemption.
          * ``pending_incoming`` lists (l, kv, blk) for ALL queued rows
            (assigned or not): R5 applies from the append (that is what set
            page2slot to PENDING), not from the assignment.  When None, it is
            derived from ``pending_evict`` (legacy semantics verbatim).
          R6  claim retention.   for every assigned row (l, kv, h) -> (b, g)
                                 whose generation is CURRENT (gen[b] == g):
                                 owner[l, kv, h] != 0.  An assigned,
                                 unsuperseded transfer whose owner word is
                                 free means a claim was LOST (two batches
                                 could assign the same slot -> wrong-V).
        """
        layers = list(range(self.L)) if layer is None else [layer]
        pend = pending_evict if pending_evict is not None else {}
        inc = pending_incoming if pending_incoming is not None else \
            [(k[0], k[1], v[0]) for k, v in pend.items()]
        for l in layers:
            for kv in range(self.n_kv):
                s2p = self.slot2page[l, kv]
                p2s = self.page2slot[l, kv]
                own = self.owner[l, kv]
                occ = (s2p >= 0) & (own == 0)
                pages = s2p[occ].long()
                # R2: one page per slot -- occupied slots hold distinct pages
                if pages.numel() != torch.unique(pages).numel():
                    raise AssertionError(
                        f"I3 residency: layer {l} kv {kv} has two slots holding "
                        "the same page (slot2page not injective)")
                # R1: mutual inverse, page2slot[slot2page[slot]] == slot
                slots = torch.nonzero(occ, as_tuple=False).flatten()
                back = p2s[pages]
                if not torch.equal(back, slots.to(back.dtype)):
                    raise AssertionError(
                        f"I2 residency: layer {l} kv {kv} page2slot/slot2page "
                        "are not mutual inverses (install broke single-owner)")
                # R3: every ADVERTISED page back-references the slot that
                # records it (page2slot -> slot2page direction).
                adv = torch.nonzero(p2s >= 0, as_tuple=False).flatten()
                if adv.numel():
                    hs = p2s[adv].long()
                    if bool(((hs < 0) | (hs >= self.S)).any()):
                        raise AssertionError(
                            f"I2 residency: layer {l} kv {kv} page2slot holds an "
                            f"out-of-range slot id (S={self.S})")
                    bad = s2p[hs] != adv.to(s2p.dtype)
                    if bool(bad.any()):
                        b0 = int(adv[bad][0])
                        h0 = int(p2s[b0])
                        raise AssertionError(
                            f"I2 residency: layer {l} kv {kv} page {b0} is "
                            f"advertised at slot {h0}, but slot2page[{h0}]="
                            f"{int(s2p[h0])} -- the slot's BYTES belong to a "
                            "different page than page2slot claims")
                # R4: claimed (in-flight) slots.
                fly = (s2p >= 0) & (own != 0)
                if bool(fly.any()):
                    fsl = torch.nonzero(fly, as_tuple=False).flatten()
                    fb = p2s[s2p[fly].long()]
                    outgoing = fb == fsl.to(fb.dtype)
                    if bool((~((fb < 0) | outgoing)).any()):
                        raise AssertionError(
                            f"I2 residency: layer {l} kv {kv} has an in-flight "
                            "slot whose page is already resident elsewhere")
                    for h in fsl[outgoing].tolist():
                        if (l, kv, int(h)) not in pend:
                            raise AssertionError(
                                f"I2 residency: layer {l} kv {kv} slot {h} is "
                                "CLAIMED while still advertising its old page, "
                                "and no graph-head evict is queued for it (a "
                                "deferred eviction was LOST)")
        # R5: the incoming page of every queued row (assigned or not) is never
        # advertised -- the append set page2slot to PENDING, so advertisement
        # of the same page anywhere is exactly the in-flight-bytes hazard.
        want = set(layers)
        for pl, pkv, pblk in inc:
            if pl not in want:
                continue
            cur = int(self.page2slot[pl, pkv, pblk])
            if cur >= 0:
                raise AssertionError(
                    f"I2 residency: layer {pl} kv {pkv} page {pblk} is queued "
                    f"for transport but is ALREADY advertised as resident at "
                    f"slot {cur} (in-flight bytes readable)")
        # R6 (K7): claim retention -- an assigned, current-generation row must
        # still hold its owner claim; a freed owner means the claim was LOST
        # and a later batch could assign the same slot (wrong-V class).
        for (pl, pkv, ph), (pblk, pgen) in pend.items():
            if pl not in want:
                continue
            if int(self.gen[pblk]) == int(pgen) \
                    and int(self.owner[pl, pkv, ph]) == 0:
                raise AssertionError(
                    f"I2 residency: layer {pl} kv {pkv} slot {ph} has an "
                    f"ASSIGNED in-flight transfer of page {pblk} (current "
                    f"generation) but its owner claim is FREE -- the claim "
                    f"was lost; a later batch could assign this slot")

    def bytes_report(self) -> str:
        return (f"hot={self.hot_gib:.3f}GiB (S={self.S} slots/kv, "
                f"working-set bound) maps={self.maps_gib:.3f}GiB "
                f"(NB={self.NB} int8/int32 bookkeeping)")
