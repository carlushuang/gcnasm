// v153 -- REVERT to v140 champion (93.91 TFLOPS, CHUNK=2) EXACTLY, then apply the
// round-35 reviewer's mandated NEXT lever: a ZERO-LIVENESS PV priority split that
// briefly DROPS priority around ONLY the two V global_load issue slots of each
// D-tile, with NO extra V fragment carried live across any WMMA. ROUND-36 (lane B).
//
// ================= WHY v150/v151/v152 ALL LOST, AND WHY THIS IS DIFFERENT ====
// Rounds 33-35 each tried to hide V-load latency by carrying MORE V state into the
// PV pressure peak, and each REGRESSED below v140's 93.91:
//   v150 (CHUNK=4, 89.82)  -- 8 V pairs in flight ahead of 8 WMMAs;
//   v151 (CHUNK=2 load-then-compute, 92.26) -- 4 V fragments live before the WMMAs;
//   v152 (distance-1 V ring, 90.65) -- 1 extra V pair live across the whole PV loop.
// The round-35 reviewer root-caused it precisely: the PV hot path already has
// v_p0/v_p1 (16 bf16), v_o[dt] (8 fp32 each), and rescale state live; ANY added V
// fragment lifetime crosses a VGPR/scoreboard threshold on RDNA4 and costs more
// resident-wave latency hiding than the prefetch buys. "Move V loads earlier /
// keep V live longer" is now a 5-version dead end (v133,v137,v138,v150,v151,v152).
// The reviewer's explicit NEXT: "Revert to v140 PV order and test ONLY a PV
// priority split around V-load issue, with no extra V fragment live across WMMAs."
//
// ================= THE LEVER (genuinely new, zero added liveness) ============
// In v140 the ENTIRE PV region runs at uniform prio 2 (raised once, held across
// all 16 WMMAs). That means this wave's TWO V global_load instructions per D-tile
// also issue at prio 2 -- so they out-arbitrate every co-resident wave's READY
// matrix WMMA for the shared issue slot. But a global_load does NOT need the matrix
// execution pipe those waves want; winning the issue slot for our load only DELAYS
// another wave's WMMA with no compensating benefit to us (the load's latency is
// covered by the scoreboard regardless of WHEN within the burst it issues). This
// is the EXACT arbitration-loss pattern v140 fixed for softmax exp2 -- now applied
// to the V loads, the one prio-2 non-matrix work left in the PV region.
//
// THE FIX (symmetric with v140's softmax-tail reasoning):
//   * Keep v140's CHUNK=2 deferred-rescale cadence and per-fragment WMMA order
//     BYTE-IDENTICAL (revert of v152's ring -- V loads are back inside the dc loop,
//     short-lived, exactly as v140).
//   * Around ONLY the two V global_loads of each D-tile, momentarily set prio 0
//     (yield the issue slot to co-resident waves' ready WMMAs), then immediately
//     RAISE BACK to prio 2 before the two PV WMMAs that consume them. The toggle
//     pair straddles ONLY the pure-memory load pair -- never a WMMA, honoring the
//     "never lower priority next to a WMMA burst" rule (the WMMAs stay prio 2).
//   * This is NOT v136/v146 (those toggled around the rescale VALU: v136 prio0
//     92.26, v146 prio1 93.26 -- both LOST). The V-LOAD issue slot has never been
//     re-prioritized; it is the untried target the reviewer named.
//
// Net PV policy: prio2 [PV WMMAs + rescale], prio0 [only the V load pair]. Zero
// extra VGPR liveness -- v_v0/v_v1 have the SAME short lifetime as v140 (consumed
// by the immediately-following WMMAs). Only two s_setprio SALU ops added per tile.
//
// ================= WHY IT IS BIT-EXACT ====================================
// __builtin_amdgcn_s_setprio(N) emits a single `s_setprio N` SALU instruction that
// ONLY changes this wave's issue-arbitration priority. It moves no data, does no
// arithmetic, reassociates no fp32 add/mul. V loads read the SAME bytes from the
// SAME addresses; every v_o[dt] receives its two WMMAs (v_v0*v_p0 then v_v1*v_p1)
// in the identical operand order; the CHUNK=2 rescale grouping is unchanged. Every
// exp2/row-sum/P-pack/O-store is byte-identical to v140. -> max_abs 0.0001, n_bad=0.
//
// ================= WIRING NOTE (inherited from v126/v132/v140) ==============
// v153 MUST be in the host dVT (pre-transposed V, layout [B,H,D,N]) allow-list;
// the kernel indexes V with vt_stride_d = k.N. Host registers v153 in BOTH the
// dispatch switch AND the dVT allow-list. (Omitting it -> max_abs=0.0360.)
#include <hip/hip_runtime.h>
#include "attn_common.h"

using bf16x8_t = bf16_t __attribute__((ext_vector_type(8)));
using fp32x8_t = fp32_t __attribute__((ext_vector_type(8)));

__device__ static inline bf16_t bf16_fast153(fp32_t f) {
    unsigned int x = __builtin_bit_cast(unsigned int, f);
    x += 0x7FFF + ((x >> 16) & 1);
    return static_cast<bf16_t>(x >> 16);
}

__device__ static inline fp32_t v153_cross_half_max(fp32_t v) {
    int x = __builtin_bit_cast(int, v);
    int other = __builtin_amdgcn_ds_bpermute((threadIdx.x ^ 16) << 2, x);
    return __builtin_fmaxf(v, __builtin_bit_cast(fp32_t, other));
}

__device__ static inline fp32_t v153_cross_half_sum(fp32_t v) {
    int x = __builtin_bit_cast(int, v);
    int other = __builtin_amdgcn_ds_bpermute((threadIdx.x ^ 16) << 2, x);
    return v + __builtin_bit_cast(fp32_t, other);
}

template<class T>
__launch_bounds__(T::BLOCK_SIZE, 1)
__global__ void opus_attn_gfx1201_kernel_v153(opus_attn_kargs k)
{
#if defined(__gfx1201__) || defined(__gfx1200__)
    constexpr int BLOCK_M = T::BLOCK_M;
    constexpr int BLOCK_N = T::BLOCK_N;
    constexpr int W_K     = T::W_K;
    constexpr int DK      = T::D_TILES_K;

    const int tid     = static_cast<int>(threadIdx.x);
    const int wave_id = tid / 32;
    const int lane    = tid % 32;
    const int col16   = lane % 16;
    const int row_grp = lane / 16;
    const int row8    = row_grp * 8;

    const int q_tile_id = blockIdx.x;
    const int h         = blockIdx.y;
    const int b         = blockIdx.z;

    const int stride_n = k.D;
    const int stride_h = k.N * k.D;
    const int stride_b = k.H * k.N * k.D;

    const bf16_t* __restrict__ Qp = reinterpret_cast<const bf16_t*>(k.ptr_q) + b * stride_b + h * stride_h;
    const bf16_t* __restrict__ Kp = reinterpret_cast<const bf16_t*>(k.ptr_k) + b * stride_b + h * stride_h;
    bf16_t*       __restrict__ Op = reinterpret_cast<bf16_t*>(k.ptr_o) + b * stride_b + h * stride_h;

    const int vt_stride_d = k.N;
    const int vt_stride_h = k.D * k.N;
    const int vt_stride_b = k.H * k.D * k.N;
    const bf16_t* __restrict__ VTp = reinterpret_cast<const bf16_t*>(k.ptr_v) + b * vt_stride_b + h * vt_stride_h;

    const int q_m_base = q_tile_id * BLOCK_M + wave_id * 16;
    const bf16_t* q_row = Qp + (q_m_base + col16) * stride_n;
    bf16x8_t v_q[DK];
    constexpr fp32_t LOG2_E = 1.44269504088896340736f;
    const fp32_t qscale = k.scale * LOG2_E;
    #pragma unroll
    for (int kt = 0; kt < DK; ++kt) {
        v_q[kt] = *reinterpret_cast<const bf16x8_t*>(&q_row[kt * W_K + row8]);
        #pragma unroll
        for (int j = 0; j < 8; ++j)
            v_q[kt][j] = bf16_fast153(bf16_to_f32(v_q[kt][j]) * qscale);
    }

    fp32x8_t v_o[DK];
    #pragma unroll
    for (int kt = 0; kt < DK; ++kt) {
        #pragma unroll
        for (int j = 0; j < 8; ++j) v_o[kt][j] = 0.0f;
    }
    fp32_t m_row = -3.4e38f;
    fp32_t l_row = 0.0f;

    const int num_kv_tiles = k.N / BLOCK_N;

    for (int n_tile = 0; n_tile < num_kv_tiles; ++n_tile) {
        const int n_base = n_tile * BLOCK_N;

        fp32x8_t v_s0 = {0,0,0,0,0,0,0,0};
        fp32x8_t v_s1 = {0,0,0,0,0,0,0,0};

        // QK^T is bubble-prone (2 chains, depth DK, gated on K loads) -> highest
        // priority so a ready QK^T WMMA wins the shared matrix-pipe issue slot.
        // v132: raise BEFORE the K preloads (v131 raised it after), so the FIRST
        // QK^T WMMA -- the one most exposed to K-load latency -- also issues at
        // prio 2 instead of the default priority. s_setprio only affects
        // instructions issued after it, so its placement matters for the head.
        __builtin_amdgcn_s_setprio(2);

        // ---- QKT with software-pipelined K loads (v63) ----
        // Preload D-tile 0 K data, then prefetch the next D-tile while the
        // current WMMA executes, hiding global K-load latency.
        bf16x8_t v_k0_next = *reinterpret_cast<const bf16x8_t*>(Kp + (n_base + col16) * stride_n + row8);
        bf16x8_t v_k1_next = *reinterpret_cast<const bf16x8_t*>(Kp + (n_base + 16 + col16) * stride_n + row8);

        #pragma unroll
        for (int kt = 0; kt < DK; ++kt) {
            bf16x8_t v_k0 = v_k0_next;
            bf16x8_t v_k1 = v_k1_next;
            if (kt + 1 < DK) {
                v_k0_next = *reinterpret_cast<const bf16x8_t*>(Kp + (n_base + col16) * stride_n + (kt+1) * W_K + row8);
                v_k1_next = *reinterpret_cast<const bf16x8_t*>(Kp + (n_base + 16 + col16) * stride_n + (kt+1) * W_K + row8);
            }
            v_s0 = __builtin_amdgcn_wmma_f32_16x16x16_bf16_w32_gfx12(v_k0, v_q[kt], v_s0);
            v_s1 = __builtin_amdgcn_wmma_f32_16x16x16_bf16_w32_gfx12(v_k1, v_q[kt], v_s1);
        }

        // Softmax HEAD = cross-lane row-max reduction (ds_bpermute) + new_m +
        // l_row rescale. Short, genuinely yieldable, and GATES the exp2 below ->
        // keep at prio 0 so other waves' ready matrix work wins these slots (this
        // wave is not yet on its exp2 critical path here). (No WMMA adjacent ->
        // honors "never lower priority next to a WMMA burst".)
        __builtin_amdgcn_s_setprio(0);
        fp32_t row_max = v_s0[0];
        #pragma unroll
        for (int j = 1; j < 8; ++j) row_max = __builtin_fmaxf(row_max, v_s0[j]);
        #pragma unroll
        for (int j = 0; j < 8; ++j) row_max = __builtin_fmaxf(row_max, v_s1[j]);
        row_max = v153_cross_half_max(row_max);

        const fp32_t new_m = __builtin_fmaxf(m_row, row_max);
        fp32_t rescale = 1.0f;
        const bool need_rescale = (new_m != m_row);
        if (need_rescale) {
            rescale = __builtin_amdgcn_exp2f(m_row - new_m);
            l_row *= rescale;
            // NOTE: the v_o rescale is NOT done here (v100 did all 8 fragments in
            // one VALU block). v131 defers it into 2-tile chunks interleaved with
            // the PV loop below -> only 2 O fragments hot per VALU region.
        }
        m_row = new_m;

        // Softmax TAIL = the 16 bulk exp2 transcendentals + row-sum fold + bf16
        // P-pack. These sit on the direct QK^T->PV critical path (PV needs v_p =
        // bf16(exp2(...))). exp2 issues to the TRANSCENDENTAL pipe, not the matrix
        // pipe, so it co-executes in the WMMA issue shadow (playbook lever 2/6).
        // v132 ran this at prio 0, where it loses issue arbitration to every
        // co-resident wave's prio-2 matrix work -- a pure arbitration loss that
        // stretches this wave's QK->PV gap with no compensating matrix benefit.
        // v140 raises it to the UNTRIED middle level 1: above other waves' prio-0
        // bookkeeping (so this wave's critical-path exp2 is no longer starved),
        // but still BELOW prio-2 matrix work (so it yields the matrix issue slot
        // to other waves' QK^T/PV -- avoiding v134's mistake of stealing matrix
        // slots with feeder VALU at prio 2). exp2 needs the transcendental pipe,
        // which those WMMAs do not contend for.
        __builtin_amdgcn_s_setprio(1);

        #pragma unroll
        for (int j = 0; j < 8; ++j) v_s0[j] = __builtin_amdgcn_exp2f(v_s0[j] - new_m);
        #pragma unroll
        for (int j = 0; j < 8; ++j) v_s1[j] = __builtin_amdgcn_exp2f(v_s1[j] - new_m);

        fp32_t row_sum = v_s0[0];
        #pragma unroll
        for (int j = 1; j < 8; ++j) row_sum += v_s0[j];
        #pragma unroll
        for (int j = 0; j < 8; ++j) row_sum += v_s1[j];
        row_sum = v153_cross_half_sum(row_sum);
        l_row += row_sum;

        bf16x8_t v_p0, v_p1;
        #pragma unroll
        for (int j = 0; j < 8; ++j) v_p0[j] = bf16_fast153(v_s0[j]);
        #pragma unroll
        for (int j = 0; j < 8; ++j) v_p1[j] = bf16_fast153(v_s1[j]);

        // ---- PV: chunked rescale interleaved with WMMAs (v131) ----
        // CHUNK D-tiles per group: rescale just this chunk's O fragments (VALU),
        // then issue the chunk's V loads + PV WMMAs. The next chunk's rescale
        // overlaps this chunk's WMMAs in the matrix-pipe shadow, and no single
        // VALU region touches more than CHUNK fragments -> tighter live ranges.
        // PV is matrix-pipe work just like QK^T. v131 held it at prio 1 on the
        // theory its 8-chain ILP lets it yield; v132 raises it to prio 2 (uniform
        // with QK^T). Rationale: within a wave QK^T and PV are temporally disjoint
        // (softmax island at prio 0 between them), so there is no intra-wave
        // contention to break; ACROSS resident waves, demoting PV to 1 only makes
        // this wave's PV WMMAs lose the shared slot to other waves' equal-value
        // matrix work, lengthening the PV critical path for no compensating gain.
        // All PV WMMAs stay prio 2 (HW round-robins them fairly). v153 toggle below
        // straddles ONLY the V load pair, NEVER a WMMA -- so the matrix burst is
        // still uniformly prio 2 (v136's per-chunk toggle regressed because it
        // toggled around the rescale VALU, a different target).
        __builtin_amdgcn_s_setprio(2);
        constexpr int CHUNK = 2;
        #pragma unroll
        for (int c0 = 0; c0 < DK; c0 += CHUNK) {
            if (need_rescale) {
                #pragma unroll
                for (int dc = 0; dc < CHUNK; ++dc) {
                    const int dt = c0 + dc;
                    #pragma unroll
                    for (int j = 0; j < 8; ++j) v_o[dt][j] *= rescale;
                }
            }
            #pragma unroll
            for (int dc = 0; dc < CHUNK; ++dc) {
                const int dt = c0 + dc;
                // v153: yield the issue slot to co-resident waves' ready WMMAs for
                // ONLY the two V global_loads (they need no matrix pipe), then raise
                // back to prio2 for the two PV WMMAs that consume them. v149 trick:
                // vt_addr1 = vt_addr0 + 16 (+32B folds into the load immediate offset,
                // reuses the base-addr VGPR). V lifetime is the SAME as v140 -- the
                // loads are immediately followed by the WMMAs (no carried fragment).
                const bf16_t* vt_addr0 = VTp + (dt * W_K + col16) * vt_stride_d + n_base + row8;
                __builtin_amdgcn_s_setprio(0);
                bf16x8_t v_v0 = *reinterpret_cast<const bf16x8_t*>(vt_addr0);
                bf16x8_t v_v1 = *reinterpret_cast<const bf16x8_t*>(vt_addr0 + 16);
                __builtin_amdgcn_s_setprio(2);
                v_o[dt] = __builtin_amdgcn_wmma_f32_16x16x16_bf16_w32_gfx12(v_v0, v_p0, v_o[dt]);
                v_o[dt] = __builtin_amdgcn_wmma_f32_16x16x16_bf16_w32_gfx12(v_v1, v_p1, v_o[dt]);
            }
        }
    }

    // Epilogue is pure VALU + global store, no WMMA -> priority 0.
    __builtin_amdgcn_s_setprio(0);
    const fp32_t inv = (l_row > 0.0f) ? (1.0f / l_row) : 0.0f;
    bf16_t* o_row = Op + (q_m_base + col16) * stride_n;
    #pragma unroll
    for (int dt = 0; dt < DK; ++dt) {
        bf16x8_t o_pack;
        #pragma unroll
        for (int j = 0; j < 8; ++j) o_pack[j] = bf16_fast153(v_o[dt][j] * inv);
        *reinterpret_cast<bf16x8_t*>(&o_row[dt * W_K + row8]) = o_pack;
    }
#else
    (void)k;
#endif
}
