# -*- coding: utf-8 -*-
"""
bm4d_cuda.py -- GPU-accelerated BM4D volumetric denoising
============================================================
Single .py file. Dependencies: CuPy, NumPy, PyWavelets, SciPy (host-side
only -- never touches the GPU hot path).

    from bm4d_cuda import bm4d   # usage: bm4d(data, sigma)

------------------------------------------------------------------------
REVISION 3 -- PARALLEL BLOCK-MATCHING SEARCH + BLOCK-COOPERATIVE WIENER
------------------------------------------------------------------------
Measured starting point for this revision (100^3 volume, sigma=0.08,
default parameters): GPU f32 2.56 s (14.4x vs. the real bm4d CPU
reference's 36.9 s), GPU f64 5.53 s (6.7x), PSNR/correlation against
the CPU reference unchanged from prior revisions (36.74 dB / 0.9997).

Revision 2 parallelized the HT stage's transform/threshold/inverse
across bs^3 threads per block, but left block-matching SEARCH entirely
serial: thread 0 alone scanned the whole search window (up to 3375
candidates at search_r=7) while every other thread in the block sat
idle, and the Wiener stage wasn't block-cooperative at all -- it was
still one thread per reference position doing search AND the entire
transform pipeline serially, in up to ~64-128 KB of slow per-thread
local memory (a block-cooperative Wiener attempt was tried and
reverted; see the historical note preserved below).

This revision changes two things:

1. BLOCK-MATCHING SEARCH IS NOW PARALLEL (parallel_search_and_merge,
   used by both HT and Wiener). Each thread in the block computes SSDs
   for a contiguous shard of the search window and keeps a small LOCAL
   bounded top-max_stack list; thread 0 then merges the nthreads local
   lists via a linear-merge chain in shared memory. This is PROVABLY
   exact (a candidate evicted from a thread's local top-max_stack list
   can never be in the true global top-max_stack either, since ranking
   within any subset can only be >= ranking within the full set) and
   was verified against a NumPy re-implementation of the exact
   add_stack/saturating-counter semantics across 90,000+ randomized
   trials, including adversarial cases where every qualifying candidate
   lands in a single thread's shard -- zero mismatches against both
   brute-force top-K and the original serial algorithm.

2. THE WIENER STAGE IS NOW BLOCK-COOPERATIVE (Revision 3's
   bm4d_wiener_f32_v3/f64_v3), fixing what actually made the earlier
   block-cooperative attempt slower: that attempt already used
   separable per-pass transforms but still synchronized once PER k
   PER pass (up to ~192 barriers/block at max_stack=32). Here, each
   pass reads all K group members into a small per-thread tmp[] array,
   syncs ONCE, writes all K back, syncs ONCE -- O(1) syncs per pass
   regardless of K, not O(K). Combined with parallelizing the search
   (which the earlier attempt didn't touch) and switching the spatial
   transform from Revision 1's direct triple-contraction (O(bs^6) work
   per group member) to the same separable technique the HT stage
   already uses (O(bs^4)) -- verified independently in NumPy to agree
   with the direct method to ~1e-15, both directions, single- and
   dual-buffer -- this should no longer lose to Revision 1's fully
   serial, ~64-128 KB-per-thread design.

At full per-voxel search parallelism, Wiener v3's shared-memory need
(~64 KB f32, ~80 KB with default parameters for f64) exceeds the 48 KB
available without opting into the dynamic-shared-memory extension, which
only compute capability >= 7.0 (Volta+) supports. Rather than simply
falling back below that line, the search-worker thread count (n_search)
is decoupled from the block's total thread count and adapts to whatever
budget is actually available: full width when there's room, otherwise
the widest multiple-of-32 search width that still fits -- shrinking
search parallelism, never max_stack (which would change denoising
quality). This is a free trade on constrained hardware: Wiener's fixed
per-block transform buffers (group_basic + group_noisy) are what
actually gate reachability -- 32 KB for f32, 64 KB for f64 -- and
search-staging memory can be shrunk independently of them. Concretely,
on a Pascal GTX 1080 Ti (48 KB, no opt-in above that), f32 Wiener v3
lands at n_search=64 (2 warps) in ~33 KB and runs -- verified end to
end, 1.73x faster than the parallel-search-only version and PSNR/
correlation still exactly unchanged; f64's 64 KB transform buffers
alone exceed the 48 KB ceiling with nothing left to trade, so f64 still
falls back to Revision 1 there, unavoidably, without reducing
max_stack_wiener. On anything Volta or newer with enough headroom, this
reduces to exactly the original fixed-width design (n_search == bs^3).
The Python launcher queries the device's actual opt-in ceiling at
runtime and computes this automatically; call bm4d(..., verbose=True)
to see which width, if any, was chosen. The HT stage's shared-memory
footprint (~17-21 KB with default parameters, dominated by the
search-merge staging buffer, not
by the transform buffer) still fits under the no-opt-in-needed 48 KB
ceiling, so it has no fallback path and needs none.

NUMERICAL EQUIVALENCE, precisely stated: every individual SSD, every
transform coefficient, and the retained-coefficient count/threshold
logic are computed with the exact same arithmetic as before -- only
WHICH thread computes which value, and the scheduling of
__syncthreads() around it, changed. The ONE exception is the Wiener
stage's sum_omega2 (used for the final aggregation weight): Revision 1
summed it in a single serial loop in a fixed order; here it's
accumulated as nthreads partial sums combined via atomicAdd, which
(floating-point addition not being associative) can shift the last bit
or two relative to Revision 1. This is called out explicitly rather
than glossed over, per this file's own standard of documenting exactly
what is and isn't bit-identical -- and it's several orders of magnitude
smaller than the ~0.13 dB gap already measured against the real bm4d
reference.

CONSTANT-ARRAY CACHING: the Kaiser window, the spatial transform matrix
(bior1.5 for HT, DCT-n for Wiener), and the Haar matrix bank are pure
functions of (bs and/or max_stack, dtype) with no dependence on the
volume being denoised, but were being rebuilt on the host and
re-uploaded to the GPU on every bm4d() call regardless. They're now
cached (keyed additionally on the active device id, since -- unlike
_get_kernel's RawKernel cache, which CuPy recompiles per-device
internally -- a cp.ndarray is physically resident on one specific
device and a cache that ignored device id would silently hand back the
wrong device's array under multi-GPU use). This changes only when
those arrays are built, never their content, so it has no effect on
any numerical result.

------------------------------------------------------------------------
REVISION 2 HISTORY (block-cooperative HT, shared-memory architecture)
------------------------------------------------------------------------
Revision 1 (one thread per reference position, doing search + transform
+ threshold + inverse + scatter entirely serially, in per-thread LOCAL
memory) was deliberately correctness-first, not fast: up to ~64-128 KB
of slow, DRAM-backed local memory per thread for the Wiener stage. It
worked and was verified, but the serial per-thread transform work was
always the known next target.

Revision 2: ONE BLOCK per reference-cube position, block shape
(bs,bs,bs) -- one thread per voxel within the patch. Thread (0,0,0)
did the block-matching search (serial -- superseded by Revision 3's
parallel search, above) and wrote matched positions to shared memory.
All threads cooperated on loading, transforming, thresholding/
shrinking, inverse-transforming, and aggregating -- using shared
memory instead of per-thread local memory.

The 3D spatial transform is applied as three separable, in-place passes
-- the same pattern used by a real, independently-authored, MIT-licensed
BM4D CUDA implementation (Tananaev, 2024) for its DCT kernel, adopted
here after independently verifying (in Python, before any CUDA was
written) that this separable in-place approach is mathematically
identical to the direct triple-tensor-contraction approach used in
Revision 1 (machine-precision agreement). The 1D Haar transform across
the group axis, and the threshold/shrinkage/aggregation steps, are also
done in-place per spatial position -- safe because each thread's own
(i,j,l) slice across all K matches is never touched by any other
thread.

UPDATE (post-benchmarking on real hardware, pre-Revision-3): the Wiener
stage was originally split -- float32 on a block-cooperative
shared-memory design, float64 forced onto the older per-thread
local-memory design purely because its buffers (two live spectra sized
max_stack_wiener * bs^3 = 32*125 doubles = 64 KB) exceed Pascal's 48 KB
shared-memory ceiling. Wall-clock testing showed the block-cooperative
design's synchronization cost (~192 __syncthreads() barriers per block,
from three separable-axis passes x two syncs each x up to max_stack=32
group members) made it ~2x SLOWER than Revision 1 at this problem size
(bs=5), for identical PSNR/correlation against the real bm4d reference
-- the synchronization bought zero accuracy, only latency. That
kernel was removed; both dtypes ran Revision 1 until this file's
Revision 3 (above) fixed the actual root cause (O(K) syncs, and a
serial search hidden inside Revision 1 that a naive port would have
inherited) rather than reverting to it.

Verified against the already-validated per-thread kernel-mirror before
translation: max diff 4.4e-16 (machine precision) for the block-
cooperative restructuring, confirming the reorganization changed only
parallelization, not mathematics. (This refers to the HT-stage
restructuring, and to the original block-cooperative Wiener attempt
while it existed -- both were mathematically equivalent to Revision 1,
just slower in practice for Wiener at this bs/max_stack combination,
until Revision 3 fixed why.)

------------------------------------------------------------------------
CORRECTNESS VERIFICATION SUMMARY (unchanged from Rev 1, still the basis
for every kernel below)
------------------------------------------------------------------------
Transform matrices (bior1.5 n=4, DCT n=5, Haar for group sizes up to
32) verified orthonormal and, for bior1.5, verified to reproduce
Makinen's own hardcoded reference matrix bit-for-bit. A full Python
reference (Lebrun IPOL 2012 formulas + Makinen's exact default
parameters) checked against the real bm4d package. Block-matching
selection verified against brute-force top-K over 5000 randomized
trials (Revision 1/2), and the Revision 3 parallel-search+merge
restructuring separately verified against both brute-force top-K and
the original serial algorithm over 90,000+ randomized trials (see
above). Statistically rigorous multi-trial validation (n=24-50 across
varying sigma and signal structure): HT-stage-only gap -0.035+-0.072 dB
(indistinguishable from zero); full-pipeline gap on moderate synthetic
data not statistically distinguishable from zero (p=0.143, n=24); a
real, isolated ~0.47 dB Wiener-stage-specific gap on edge-heavy
realistic seismic data, empirically tested against four concrete
mechanisms (parameter scaling, DC-preservation, the gamma block-
matching correction factor, and the PSD/residual reprocessing
pipeline) -- all four ruled out directly against the real package's
own behaviour, not by assumption. The remaining gap traces to
mechanisms inside a closed, non-commercially-licensed binary that
cannot be further investigated without reverse-engineering proprietary
code, which is not attempted.

References
----------
Dabov, Foi, Katkovnik, Egiazarian (2007). IEEE TIP 16(8), 2007-2080.
Lebrun (2012). IPOL 2, 175-213. https://doi.org/10.5201/ipol.2012.l-bm3d
Maggioni, Katkovnik, Egiazarian, Foi (2013). IEEE TIP 22(1), 119-133.
Makinen, Azzari, Foi (2020). IEEE TIP 29, 8339-8354.
Tananaev (2024). bm4d-gpu (MIT license) -- block-matching and separable
    in-place transform architecture.
"""
import numpy as np
import cupy as cp
from safety import validate_parameters

try:
    import pywt
except ImportError:
    pywt = None


# =========================================================================
# Host-side transform matrix construction (one-time, negligible cost)
# =========================================================================
_BIOR15_4 = np.array([
    [0.5, 0.5, 0.5, 0.5],
    [0.5, 0.5, -0.5, -0.5],
    [0.70710677, -0.70710677, 0.0, 0.0],
    [0.0, 0.0, 0.70710677, -0.70710677]
], dtype=np.float64)


def _haar_matrix(n: int) -> np.ndarray:
    if n == 1:
        return np.array([[1.0]])
    if pywt is None:
        raise ImportError("PyWavelets is required to build the grouping-dimension transform.")
    t = np.zeros((n, n))
    level = int(np.log2(n))
    for i in range(n):
        e = np.zeros(n)
        e[0] = 1.0
        e = np.roll(e, i)
        coeffs = pywt.wavedec(e, 'haar', mode='periodization', level=level)
        t[:, i] = np.hstack(coeffs)
    return t


def _dct_matrix(n: int) -> np.ndarray:
    from scipy.fft import dct
    return dct(np.eye(n), norm='ortho').T


def _kaiser_3d(bs: int, beta: float = 2.0) -> np.ndarray:
    k1d = np.kaiser(bs, beta)
    return (k1d[:, None, None] * k1d[None, :, None] * k1d[None, None, :]).astype(np.float64)


_HAAR_CACHE = {}
def _haar(n):
    if n not in _HAAR_CACHE:
        _HAAR_CACHE[n] = _haar_matrix(n)
    return _HAAR_CACHE[n]


def _build_haar_bank(max_stack):
    sizes = [1]
    while sizes[-1] < max_stack:
        sizes.append(sizes[-1] * 2)
    flat_parts, offsets = [], []
    off = 0
    for s in sizes:
        H = _haar(s).astype(np.float64).ravel()
        flat_parts.append(H)
        offsets.append(off)
        off += s * s
    return np.concatenate(flat_parts), np.array(offsets, dtype=np.int32)


def _ref_grid(n, bs, step):
    if n < bs or step < 1 or step > bs:
        raise ValueError("Reference grid requires n >= block size and 1 <= step <= block size")
    positions = list(range(0, n - bs + 1, step))
    if positions[-1] != n - bs:
        positions.append(n - bs)
    return sorted(set(positions))


# =========================================================================
# CUDA source
# =========================================================================
_CUDA_SOURCE = b"""
template <typename T>
__device__ __forceinline__ void add_stack(
    T* stack_dist, int* stack_z, int* stack_y, int* stack_x, int* n,
    T val_dist, int val_z, int val_y, int val_x, int maxN
) {
    int k;
    if (*n < maxN) {
        k = *n; (*n)++;
        while (k > 0 && val_dist > stack_dist[k-1]) {
            stack_dist[k] = stack_dist[k-1];
            stack_z[k] = stack_z[k-1]; stack_y[k] = stack_y[k-1]; stack_x[k] = stack_x[k-1];
            k--;
        }
        stack_dist[k] = val_dist; stack_z[k] = val_z; stack_y[k] = val_y; stack_x[k] = val_x;
    } else if (val_dist >= stack_dist[0]) {
        return;
    } else {
        k = 1;
        while (k < maxN && val_dist < stack_dist[k]) {
            stack_dist[k-1] = stack_dist[k];
            stack_z[k-1] = stack_z[k]; stack_y[k-1] = stack_y[k]; stack_x[k-1] = stack_x[k];
            k++;
        }
        stack_dist[k-1] = val_dist; stack_z[k-1] = val_z; stack_y[k-1] = val_y; stack_x[k-1] = val_x;
    }
}

#define MAX_STACK 32

__device__ __forceinline__ int largest_pow2_leq(int n) {
    if (n < 1) return 0;
    int p = 1;
    while (p * 2 <= n) p *= 2;
    return p;
}

// =========================================================================
// REVISION 3 -- PARALLEL BLOCK-MATCHING SEARCH
// =========================================================================
// In Revisions 1/2, block-matching search was done by a SINGLE thread
// (thread 0) scanning the entire search window serially, while every other
// thread in the block (63 of 64 for bs=4, 124 of 125 for bs=5) sat idle.
// For search_r=7 that is a 15x15x15=3375-candidate window; at bs=5 each
// candidate costs a 125-multiply-add SSD, i.e. ~422K serial multiply-adds
// on one thread before any other thread does anything.
//
// This function instead splits the (identically-ordered, cz-major/
// cy-mid/cx-minor) candidate list into nthreads contiguous shards, one per
// thread. Each thread computes full SSDs for its own shard and keeps a
// LOCAL bounded top-max_stack list (using the exact same add_stack<T>
// insertion logic the serial version already uses -- so a candidate that
// would be evicted from the local list is provably never in the true
// global top-max_stack either, since ranking within a subset can only be
// >= its ranking within the full set). Each thread also keeps an
// UNCAPPED true count of how many of its own candidates passed tau
// (needed to reproduce the serial version's *saturating* match counter
// exactly -- see below).
//
// Thread 0 then merges the nthreads local (already-sorted, already-
// bounded) lists via a chained linear merge -- O(nthreads * max_stack)
// comparisons, done once, entirely in fast shared memory -- into the
// same final s_dist/s_z/s_y/s_x arrays and s_n/s_K scalars the rest of
// the kernel already expects, so nothing downstream of this function
// needs to change.
//
// Exactness: verified against a NumPy-level re-implementation of the
// exact add_stack semantics (including the saturating match counter)
// across 90,000+ randomized trials -- uniform-random distances, and
// adversarial cases where every qualifying candidate lands in a single
// thread's shard -- with zero mismatches against both a brute-force
// top-K and the original single-stream serial algorithm. This function
// changes only WHICH thread computes which candidate's SSD and the
// scheduling of the merge; every individual SSD value is computed with
// the exact same arithmetic as before.
// =========================================================================
template <typename T>
__device__ __forceinline__ void parallel_search_and_merge(
    const T* __restrict__ match_vol,
    const T* __restrict__ ref_cube,
    int nz, int ny, int nx, int bs, int cube_vol,
    int rz, int ry, int rx, int search_r, T tau, int max_stack,
    int tid, int n_search,
    T* __restrict__ stage_dist, int* __restrict__ stage_z, int* __restrict__ stage_y, int* __restrict__ stage_x,
    int* __restrict__ stage_n, int* __restrict__ stage_ntrue,
    T* __restrict__ s_dist, int* __restrict__ s_z, int* __restrict__ s_y, int* __restrict__ s_x,
    int* s_n_out, int* s_K_out
) {
    // n_search is the number of threads that actually participate in the
    // search/staging phase -- NOT necessarily equal to the block's total
    // thread count (nthreads/cube_vol). It's always <= nthreads, and is
    // n_search == nthreads (full per-voxel parallelism) whenever there's
    // shared-memory budget for it; the launcher shrinks it only when
    // needed so the search-staging buffer (which scales with n_search,
    // not with cube_vol) fits a tight shared-memory ceiling -- see
    // _wiener_v3_search_width() in the Python launcher. This changes
    // nothing about exactness: the proof (and its 90,000+-trial NumPy
    // verification) never assumed any particular relationship between
    // shard count and block geometry, and was explicitly re-tested with
    // shard counts smaller than, and unrelated to, bs^3.
    int z0 = max(0, rz-search_r), z1 = min(nz-bs, rz+search_r);
    int y0 = max(0, ry-search_r), y1 = min(ny-bs, ry+search_r);
    int x0 = max(0, rx-search_r), x1 = min(nx-bs, rx+search_r);
    int nyc = y1-y0+1, nxc = x1-x0+1;
    int total_cand = (z1-z0+1)*nyc*nxc;

    if (tid < n_search) {
        int chunk = (total_cand + n_search - 1) / n_search;
        int lo = tid*chunk;
        int hi = min(total_cand, lo+chunk);

        T loc_dist[MAX_STACK];
        int loc_z[MAX_STACK], loc_y[MAX_STACK], loc_x[MAX_STACK];
        int loc_n = 0, loc_ntrue = 0;

        for (int idx = lo; idx < hi; ++idx) {
            int cz = z0 + idx/(nyc*nxc);
            int cy = y0 + (idx/nxc)%nyc;
            int cx = x0 + idx%nxc;
            T ssd = (T)0;
            for (int a = 0; a < bs; ++a)
            for (int b = 0; b < bs; ++b)
            for (int c = 0; c < bs; ++c) {
                T rv = ref_cube[a*bs*bs + b*bs + c];
                T cv = match_vol[(cz+a)*ny*nx + (cy+b)*nx + (cx+c)];
                T d = rv - cv;
                ssd += d*d;
            }
            T dist = ssd / (T)cube_vol;
            if (dist <= tau) {
                loc_ntrue++;
                add_stack<T>(loc_dist, loc_z, loc_y, loc_x, &loc_n, dist, cz, cy, cx, max_stack);
            }
        }

        for (int i = 0; i < loc_n; ++i) {
            stage_dist[tid*max_stack+i] = loc_dist[i];
            stage_z[tid*max_stack+i] = loc_z[i];
            stage_y[tid*max_stack+i] = loc_y[i];
            stage_x[tid*max_stack+i] = loc_x[i];
        }
        stage_n[tid] = loc_n;
        stage_ntrue[tid] = loc_ntrue;
    }
    __syncthreads();

    if (tid == 0) {
        long long total_true = 0;
        for (int t = 0; t < n_search; ++t) total_true += stage_ntrue[t];
        int n_global = (int)min((long long)max_stack, total_true);

        int best_n = 0;
        for (int t = 0; t < n_search; ++t) {
            int nt = stage_n[t];
            if (nt == 0) continue;
            T merged_dist[MAX_STACK];
            int merged_z[MAX_STACK], merged_y[MAX_STACK], merged_x[MAX_STACK];
            const T* td = stage_dist + t*max_stack;
            const int* tzp = stage_z + t*max_stack;
            const int* typ = stage_y + t*max_stack;
            const int* txp = stage_x + t*max_stack;
            int ia = best_n-1, ib = nt-1, m = 0;
            while ((ia >= 0 || ib >= 0) && m < max_stack) {
                bool take_a;
                if (ib < 0) take_a = true;
                else if (ia < 0) take_a = false;
                else take_a = (s_dist[ia] <= td[ib]);
                if (take_a) {
                    merged_dist[m] = s_dist[ia]; merged_z[m] = s_z[ia]; merged_y[m] = s_y[ia]; merged_x[m] = s_x[ia];
                    ia--;
                } else {
                    merged_dist[m] = td[ib]; merged_z[m] = tzp[ib]; merged_y[m] = typ[ib]; merged_x[m] = txp[ib];
                    ib--;
                }
                m++;
            }
            for (int i = 0; i < m; ++i) {
                s_dist[m-1-i] = merged_dist[i]; s_z[m-1-i] = merged_z[i]; s_y[m-1-i] = merged_y[i]; s_x[m-1-i] = merged_x[i];
            }
            best_n = m;
        }
        *s_n_out = n_global;
        *s_K_out = largest_pow2_leq(n_global);
    }
    __syncthreads();
}

extern "C" {
// =========================================================================
// HARD-THRESHOLDING (HT) STAGE -- one CUDA block per reference cube,
// bs*bs*bs threads per block. Revision 3: search is now parallelized
// (see parallel_search_and_merge above); the separable spatial transform
// now does ONE syncthreads pair per pass regardless of K (batching all K
// groups' reads before syncing, then all K writes before syncing again)
// instead of one pair PER k PER pass -- this changes only the SCHEDULING
// of already-computed values, never the arithmetic itself, so results are
// bit-identical to Revision 2 for a given match set.
// =========================================================================
__global__ void bm4d_ht_f32(
    const float* __restrict__ vol,
    float* __restrict__ numerator, float* __restrict__ denominator,
    const int nz, const int ny, const int nx,
    const int bs, const int search_r, const int max_stack,
    const float tau, const float lambda_thr, const float sigma,
    const float* __restrict__ T_spatial, const float* __restrict__ Kaiser3d,
    const int* __restrict__ ref_z, const int* __restrict__ ref_y, const int* __restrict__ ref_x,
    const int n_refs,
    const float* __restrict__ Haar_flat, const int* __restrict__ Haar_offset
) {
    const int blk = blockIdx.x;
    if (blk >= n_refs) return;
    const int rz = ref_z[blk], ry = ref_y[blk], rx = ref_x[blk];

    const int tx = threadIdx.x, ty = threadIdx.y, tz = threadIdx.z;
    const int tid = tz*bs*bs + ty*bs + tx;
    const int nthreads = bs*bs*bs;
    const int cube_vol = bs*bs*bs;

    extern __shared__ float smem_ht_f32[];
    __shared__ float s_dist[MAX_STACK];
    __shared__ int s_z[MAX_STACK], s_y[MAX_STACK], s_x[MAX_STACK];
    __shared__ int s_n, s_K, s_nret;

    float* stage_dist = smem_ht_f32;
    int* stage_z = (int*)(stage_dist + nthreads*max_stack);
    int* stage_y = stage_z + nthreads*max_stack;
    int* stage_x = stage_y + nthreads*max_stack;
    int* stage_n = stage_x + nthreads*max_stack;
    int* stage_ntrue = stage_n + nthreads;
    float* ref_cube = (float*)(stage_ntrue + nthreads);

    ref_cube[tid] = vol[(rz+tz)*ny*nx + (ry+ty)*nx + (rx+tx)];
    __syncthreads();

    parallel_search_and_merge<float>(
        vol, ref_cube, nz, ny, nx, bs, cube_vol, rz, ry, rx, search_r, tau, max_stack,
        tid, nthreads,
        stage_dist, stage_z, stage_y, stage_x, stage_n, stage_ntrue,
        s_dist, s_z, s_y, s_x, &s_n, &s_K
    );

    const int K = s_K;
    if (K == 0) return;
    const int base = s_n - K;

    float* group = smem_ht_f32;  // reuse: all Phase-A reads above are already synced-past

    for (int k = 0; k < K; ++k) {
        int cz = s_z[base+k], cy = s_y[base+k], cx = s_x[base+k];
        group[k*cube_vol + tid] = vol[(cz+tz)*ny*nx + (cy+ty)*nx + (cx+tx)];
    }
    __syncthreads();

    {
        float tmp[MAX_STACK];
        for (int k = 0; k < K; ++k) {
            float acc = 0.0f; float* cube = group + k*cube_vol;
            for (int c = 0; c < bs; ++c) acc += T_spatial[tx*bs+c]*cube[tz*bs*bs+ty*bs+c];
            tmp[k] = acc;
        }
        __syncthreads();
        for (int k = 0; k < K; ++k) group[k*cube_vol + tz*bs*bs+ty*bs+tx] = tmp[k];
        __syncthreads();

        for (int k = 0; k < K; ++k) {
            float acc = 0.0f; float* cube = group + k*cube_vol;
            for (int b = 0; b < bs; ++b) acc += T_spatial[ty*bs+b]*cube[tz*bs*bs+b*bs+tx];
            tmp[k] = acc;
        }
        __syncthreads();
        for (int k = 0; k < K; ++k) group[k*cube_vol + tz*bs*bs+ty*bs+tx] = tmp[k];
        __syncthreads();

        for (int k = 0; k < K; ++k) {
            float acc = 0.0f; float* cube = group + k*cube_vol;
            for (int a = 0; a < bs; ++a) acc += T_spatial[tz*bs+a]*cube[a*bs*bs+ty*bs+tx];
            tmp[k] = acc;
        }
        __syncthreads();
        for (int k = 0; k < K; ++k) group[k*cube_vol + tz*bs*bs+ty*bs+tx] = tmp[k];
        __syncthreads();
    }

    int haar_off = Haar_offset[31 - __clz(K)];
    {
        float tmp[MAX_STACK];
        int e = tz*bs*bs+ty*bs+tx;
        for (int i = 0; i < K; ++i) {
            float acc = 0.0f;
            for (int a = 0; a < K; ++a) acc += Haar_flat[haar_off+i*K+a]*group[a*cube_vol+e];
            tmp[i] = acc;
        }
        for (int i = 0; i < K; ++i) group[i*cube_vol+e] = tmp[i];
    }
    __syncthreads();

    if (tid == 0) s_nret = 0;
    __syncthreads();
    float thr = lambda_thr*sigma;
    int local_retained = 0;
    for (int k = 0; k < K; ++k) {
        int e = k*cube_vol + tz*bs*bs+ty*bs+tx;
        if (fabsf(group[e]) <= thr) group[e] = 0.0f; else local_retained++;
    }
    atomicAdd(&s_nret, local_retained);
    __syncthreads();
    float weight = (s_nret >= 1) ? (1.0f/(float)s_nret) : 1.0f;

    {
        float tmp[MAX_STACK];
        int e = tz*bs*bs+ty*bs+tx;
        for (int i = 0; i < K; ++i) {
            float acc = 0.0f;
            for (int a = 0; a < K; ++a) acc += Haar_flat[haar_off+a*K+i]*group[a*cube_vol+e];
            tmp[i] = acc;
        }
        for (int i = 0; i < K; ++i) group[i*cube_vol+e] = tmp[i];
    }
    __syncthreads();

    {
        float tmp[MAX_STACK];
        for (int k = 0; k < K; ++k) {
            float acc = 0.0f; float* cube = group + k*cube_vol;
            for (int a = 0; a < bs; ++a) acc += T_spatial[a*bs+tz]*cube[a*bs*bs+ty*bs+tx];
            tmp[k] = acc;
        }
        __syncthreads();
        for (int k = 0; k < K; ++k) group[k*cube_vol + tz*bs*bs+ty*bs+tx] = tmp[k];
        __syncthreads();

        for (int k = 0; k < K; ++k) {
            float acc = 0.0f; float* cube = group + k*cube_vol;
            for (int b = 0; b < bs; ++b) acc += T_spatial[b*bs+ty]*cube[tz*bs*bs+b*bs+tx];
            tmp[k] = acc;
        }
        __syncthreads();
        for (int k = 0; k < K; ++k) group[k*cube_vol + tz*bs*bs+ty*bs+tx] = tmp[k];
        __syncthreads();

        for (int k = 0; k < K; ++k) {
            float acc = 0.0f; float* cube = group + k*cube_vol;
            for (int c = 0; c < bs; ++c) acc += T_spatial[c*bs+tx]*cube[tz*bs*bs+ty*bs+c];
            tmp[k] = acc;
        }
        __syncthreads();
        for (int k = 0; k < K; ++k) group[k*cube_vol + tz*bs*bs+ty*bs+tx] = tmp[k];
        __syncthreads();
    }

    float kw = Kaiser3d[tz*bs*bs+ty*bs+tx]*weight;
    for (int k = 0; k < K; ++k) {
        int cz = s_z[base+k], cy = s_y[base+k], cx = s_x[base+k];
        float val = group[k*cube_vol + tz*bs*bs+ty*bs+tx];
        atomicAdd(&numerator[(cz+tz)*ny*nx+(cy+ty)*nx+(cx+tx)], kw*val);
        atomicAdd(&denominator[(cz+tz)*ny*nx+(cy+ty)*nx+(cx+tx)], kw);
    }
}

__global__ void bm4d_ht_f64(
    const double* __restrict__ vol,
    double* __restrict__ numerator, double* __restrict__ denominator,
    const int nz, const int ny, const int nx,
    const int bs, const int search_r, const int max_stack,
    const double tau, const double lambda_thr, const double sigma,
    const double* __restrict__ T_spatial, const double* __restrict__ Kaiser3d,
    const int* __restrict__ ref_z, const int* __restrict__ ref_y, const int* __restrict__ ref_x,
    const int n_refs,
    const double* __restrict__ Haar_flat, const int* __restrict__ Haar_offset
) {
    const int blk = blockIdx.x;
    if (blk >= n_refs) return;
    const int rz = ref_z[blk], ry = ref_y[blk], rx = ref_x[blk];

    const int tx = threadIdx.x, ty = threadIdx.y, tz = threadIdx.z;
    const int tid = tz*bs*bs + ty*bs + tx;
    const int nthreads = bs*bs*bs;
    const int cube_vol = bs*bs*bs;

    extern __shared__ double smem_ht_f64[];
    __shared__ double s_dist[MAX_STACK];
    __shared__ int s_z[MAX_STACK], s_y[MAX_STACK], s_x[MAX_STACK];
    __shared__ int s_n, s_K, s_nret;

    double* stage_dist = smem_ht_f64;
    int* stage_z = (int*)(stage_dist + nthreads*max_stack);
    int* stage_y = stage_z + nthreads*max_stack;
    int* stage_x = stage_y + nthreads*max_stack;
    int* stage_n = stage_x + nthreads*max_stack;
    int* stage_ntrue = stage_n + nthreads;
    double* ref_cube = (double*)(stage_ntrue + nthreads);

    ref_cube[tid] = vol[(rz+tz)*ny*nx + (ry+ty)*nx + (rx+tx)];
    __syncthreads();

    parallel_search_and_merge<double>(
        vol, ref_cube, nz, ny, nx, bs, cube_vol, rz, ry, rx, search_r, tau, max_stack,
        tid, nthreads,
        stage_dist, stage_z, stage_y, stage_x, stage_n, stage_ntrue,
        s_dist, s_z, s_y, s_x, &s_n, &s_K
    );

    const int K = s_K;
    if (K == 0) return;
    const int base = s_n - K;

    double* group = smem_ht_f64;

    for (int k = 0; k < K; ++k) {
        int cz = s_z[base+k], cy = s_y[base+k], cx = s_x[base+k];
        group[k*cube_vol + tid] = vol[(cz+tz)*ny*nx + (cy+ty)*nx + (cx+tx)];
    }
    __syncthreads();

    {
        double tmp[MAX_STACK];
        for (int k = 0; k < K; ++k) {
            double acc = 0.0; double* cube = group + k*cube_vol;
            for (int c = 0; c < bs; ++c) acc += T_spatial[tx*bs+c]*cube[tz*bs*bs+ty*bs+c];
            tmp[k] = acc;
        }
        __syncthreads();
        for (int k = 0; k < K; ++k) group[k*cube_vol + tz*bs*bs+ty*bs+tx] = tmp[k];
        __syncthreads();

        for (int k = 0; k < K; ++k) {
            double acc = 0.0; double* cube = group + k*cube_vol;
            for (int b = 0; b < bs; ++b) acc += T_spatial[ty*bs+b]*cube[tz*bs*bs+b*bs+tx];
            tmp[k] = acc;
        }
        __syncthreads();
        for (int k = 0; k < K; ++k) group[k*cube_vol + tz*bs*bs+ty*bs+tx] = tmp[k];
        __syncthreads();

        for (int k = 0; k < K; ++k) {
            double acc = 0.0; double* cube = group + k*cube_vol;
            for (int a = 0; a < bs; ++a) acc += T_spatial[tz*bs+a]*cube[a*bs*bs+ty*bs+tx];
            tmp[k] = acc;
        }
        __syncthreads();
        for (int k = 0; k < K; ++k) group[k*cube_vol + tz*bs*bs+ty*bs+tx] = tmp[k];
        __syncthreads();
    }

    int haar_off = Haar_offset[31 - __clz(K)];
    {
        double tmp[MAX_STACK];
        int e = tz*bs*bs+ty*bs+tx;
        for (int i = 0; i < K; ++i) {
            double acc = 0.0;
            for (int a = 0; a < K; ++a) acc += Haar_flat[haar_off+i*K+a]*group[a*cube_vol+e];
            tmp[i] = acc;
        }
        for (int i = 0; i < K; ++i) group[i*cube_vol+e] = tmp[i];
    }
    __syncthreads();

    if (tid == 0) s_nret = 0;
    __syncthreads();
    double thr = lambda_thr*sigma;
    int local_retained = 0;
    for (int k = 0; k < K; ++k) {
        int e = k*cube_vol + tz*bs*bs+ty*bs+tx;
        if (fabs(group[e]) <= thr) group[e] = 0.0; else local_retained++;
    }
    atomicAdd(&s_nret, local_retained);
    __syncthreads();
    double weight = (s_nret >= 1) ? (1.0/(double)s_nret) : 1.0;

    {
        double tmp[MAX_STACK];
        int e = tz*bs*bs+ty*bs+tx;
        for (int i = 0; i < K; ++i) {
            double acc = 0.0;
            for (int a = 0; a < K; ++a) acc += Haar_flat[haar_off+a*K+i]*group[a*cube_vol+e];
            tmp[i] = acc;
        }
        for (int i = 0; i < K; ++i) group[i*cube_vol+e] = tmp[i];
    }
    __syncthreads();

    {
        double tmp[MAX_STACK];
        for (int k = 0; k < K; ++k) {
            double acc = 0.0; double* cube = group + k*cube_vol;
            for (int a = 0; a < bs; ++a) acc += T_spatial[a*bs+tz]*cube[a*bs*bs+ty*bs+tx];
            tmp[k] = acc;
        }
        __syncthreads();
        for (int k = 0; k < K; ++k) group[k*cube_vol + tz*bs*bs+ty*bs+tx] = tmp[k];
        __syncthreads();

        for (int k = 0; k < K; ++k) {
            double acc = 0.0; double* cube = group + k*cube_vol;
            for (int b = 0; b < bs; ++b) acc += T_spatial[b*bs+ty]*cube[tz*bs*bs+b*bs+tx];
            tmp[k] = acc;
        }
        __syncthreads();
        for (int k = 0; k < K; ++k) group[k*cube_vol + tz*bs*bs+ty*bs+tx] = tmp[k];
        __syncthreads();

        for (int k = 0; k < K; ++k) {
            double acc = 0.0; double* cube = group + k*cube_vol;
            for (int c = 0; c < bs; ++c) acc += T_spatial[c*bs+tx]*cube[tz*bs*bs+ty*bs+c];
            tmp[k] = acc;
        }
        __syncthreads();
        for (int k = 0; k < K; ++k) group[k*cube_vol + tz*bs*bs+ty*bs+tx] = tmp[k];
        __syncthreads();
    }

    double kw = Kaiser3d[tz*bs*bs+ty*bs+tx]*weight;
    for (int k = 0; k < K; ++k) {
        int cz = s_z[base+k], cy = s_y[base+k], cx = s_x[base+k];
        double val = group[k*cube_vol + tz*bs*bs+ty*bs+tx];
        atomicAdd(&numerator[(cz+tz)*ny*nx+(cy+ty)*nx+(cx+tx)], kw*val);
        atomicAdd(&denominator[(cz+tz)*ny*nx+(cy+ty)*nx+(cx+tx)], kw);
    }
}

// =========================================================================
// WIENER STAGE -- REVISION 3: block-cooperative, one CUDA block per
// reference cube, bs*bs*bs threads/block (mirrors the HT kernel's
// architecture). Two changes vs. the earlier block-cooperative Wiener
// attempt that was tried and reverted (see this file's own module-level
// docstring, section "REVISION 2 HISTORY", for the full story of why),
// which is why this is expected to actually win this time:
//
//  1. Block-matching search is now parallelized (parallel_search_and_merge)
//     instead of serial thread-0-only -- previously this was hidden
//     inside Wiener's fully-serial Revision-1 design, but a serial search
//     is exactly as wasteful in a block-cooperative kernel, so it has to
//     be fixed together with the sync-count problem, not separately.
//
//  2. The separable spatial transform now batches ALL K group members
//     through a single pair of __syncthreads() per pass (read every k
//     into a small per-thread tmp[] array, ONE sync, write every k back,
//     ONE sync) instead of one sync-pair PER k PER pass. That is what
//     actually drove the previous attempt's ~192 barriers/block down to
//     O(1) regardless of K -- the earlier attempt's slowdown came from
//     literally re-deriving this same separable-pass structure but still
//     syncing inside the k-loop.
//
//  3. (Bonus, not required for the sync fix, but free once we're
//     rewriting this stage anyway): Revision 1 used the DIRECT triple-
//     tensor-contraction for the spatial transform (O(bs^6) work per
//     group member) rather than the separable 3-pass approach the HT
//     kernel already uses (O(bs^4) per member) -- verified independently
//     in NumPy (separable vs. direct, forward AND inverse, single- and
//     dual-buffer) to agree to ~1e-15, consistent with the file's
//     existing separable-transform verification. Switching Wiener to
//     separable too removes a bs^2=25x (at bs=5) redundant-FLOP factor
//     on top of the parallelization.
//
// NOTE ON NUMERICAL EQUIVALENCE: everything above preserves the exact
// per-coefficient arithmetic of Revision 1 EXCEPT sum_omega2, the scalar
// used for the final aggregation weight. Revision 1 accumulates it via a
// single serial loop over the K*cube_vol coefficients in k-major order;
// here each thread accumulates a partial sum over its own K values (for
// its own fixed spatial position) and combines partial sums via
// atomicAdd. Floating-point addition isn't associative, so this changes
// summation order and can shift the LAST bit or two of sum_omega2 (and
// therefore `weight`) relative to Revision 1 -- negligible next to the
// ~0.13 dB gap already measured against the real bm4d reference, but
// called out explicitly rather than glossed over, per this file's own
// standard of documenting exactly what is and isn't bit-identical.
// =========================================================================
__global__ void bm4d_wiener_f32_v3(
    const float* __restrict__ vol, const float* __restrict__ basic,
    float* __restrict__ numerator, float* __restrict__ denominator,
    const int nz, const int ny, const int nx,
    const int bs, const int search_r, const int max_stack,
    const float tau, const float sigma,
    const float* __restrict__ T_spatial, const float* __restrict__ Kaiser3d,
    const int* __restrict__ ref_z, const int* __restrict__ ref_y, const int* __restrict__ ref_x,
    const int n_refs,
    const float* __restrict__ Haar_flat, const int* __restrict__ Haar_offset,
    const int n_search
) {
    const int blk = blockIdx.x;
    if (blk >= n_refs) return;
    const int rz = ref_z[blk], ry = ref_y[blk], rx = ref_x[blk];

    const int tx = threadIdx.x, ty = threadIdx.y, tz = threadIdx.z;
    const int tid = tz*bs*bs + ty*bs + tx;
    const int cube_vol = bs*bs*bs;

    extern __shared__ float smem_wiener_f32[];
    __shared__ float s_dist[MAX_STACK];
    __shared__ int s_z[MAX_STACK], s_y[MAX_STACK], s_x[MAX_STACK];
    __shared__ int s_n, s_K;
    __shared__ float s_sum_omega2;

    // Staging buffer is sized by n_search (the number of threads doing
    // search work), NOT by cube_vol/nthreads (the number of threads doing
    // transform work) -- the launcher shrinks n_search below cube_vol only
    // when needed to fit a tight shared-memory ceiling; see
    // _wiener_v3_search_width() in the Python launcher. ref_cube is still
    // sized cube_vol and loaded by all cube_vol threads regardless.
    float* stage_dist = smem_wiener_f32;
    int* stage_z = (int*)(stage_dist + n_search*max_stack);
    int* stage_y = stage_z + n_search*max_stack;
    int* stage_x = stage_y + n_search*max_stack;
    int* stage_n = stage_x + n_search*max_stack;
    int* stage_ntrue = stage_n + n_search;
    float* ref_cube = (float*)(stage_ntrue + n_search);

    // search matches on `basic`, exactly like Revision 1
    ref_cube[tid] = basic[(rz+tz)*ny*nx + (ry+ty)*nx + (rx+tx)];
    __syncthreads();

    parallel_search_and_merge<float>(
        basic, ref_cube, nz, ny, nx, bs, cube_vol, rz, ry, rx, search_r, tau, max_stack,
        tid, n_search,
        stage_dist, stage_z, stage_y, stage_x, stage_n, stage_ntrue,
        s_dist, s_z, s_y, s_x, &s_n, &s_K
    );

    const int K = s_K;
    if (K == 0) return;
    const int base = s_n - K;

    // Phase-B: two buffers, reusing the same bytes as the search staging
    // (safe: all reads of stage_*/ref_cube above already happened before
    // the syncthreads() inside parallel_search_and_merge)
    float* group_basic = smem_wiener_f32;
    float* group_noisy = smem_wiener_f32 + (size_t)max_stack*cube_vol;

    for (int k = 0; k < K; ++k) {
        int cz = s_z[base+k], cy = s_y[base+k], cx = s_x[base+k];
        group_basic[k*cube_vol + tid] = basic[(cz+tz)*ny*nx + (cy+ty)*nx + (cx+tx)];
        group_noisy[k*cube_vol + tid] = vol[(cz+tz)*ny*nx + (cy+ty)*nx + (cx+tx)];
    }
    __syncthreads();

    // forward separable spatial transform, both buffers, O(1) syncs/pass
    {
        float tmp_b[MAX_STACK], tmp_n[MAX_STACK];
        for (int k = 0; k < K; ++k) {
            float ab = 0.0f, an = 0.0f;
            float* cb = group_basic + k*cube_vol; float* cn = group_noisy + k*cube_vol;
            for (int c = 0; c < bs; ++c) {
                float t = T_spatial[tx*bs+c];
                ab += t*cb[tz*bs*bs+ty*bs+c]; an += t*cn[tz*bs*bs+ty*bs+c];
            }
            tmp_b[k] = ab; tmp_n[k] = an;
        }
        __syncthreads();
        for (int k = 0; k < K; ++k) {
            group_basic[k*cube_vol + tz*bs*bs+ty*bs+tx] = tmp_b[k];
            group_noisy[k*cube_vol + tz*bs*bs+ty*bs+tx] = tmp_n[k];
        }
        __syncthreads();

        for (int k = 0; k < K; ++k) {
            float ab = 0.0f, an = 0.0f;
            float* cb = group_basic + k*cube_vol; float* cn = group_noisy + k*cube_vol;
            for (int b = 0; b < bs; ++b) {
                float t = T_spatial[ty*bs+b];
                ab += t*cb[tz*bs*bs+b*bs+tx]; an += t*cn[tz*bs*bs+b*bs+tx];
            }
            tmp_b[k] = ab; tmp_n[k] = an;
        }
        __syncthreads();
        for (int k = 0; k < K; ++k) {
            group_basic[k*cube_vol + tz*bs*bs+ty*bs+tx] = tmp_b[k];
            group_noisy[k*cube_vol + tz*bs*bs+ty*bs+tx] = tmp_n[k];
        }
        __syncthreads();

        for (int k = 0; k < K; ++k) {
            float ab = 0.0f, an = 0.0f;
            float* cb = group_basic + k*cube_vol; float* cn = group_noisy + k*cube_vol;
            for (int a = 0; a < bs; ++a) {
                float t = T_spatial[tz*bs+a];
                ab += t*cb[a*bs*bs+ty*bs+tx]; an += t*cn[a*bs*bs+ty*bs+tx];
            }
            tmp_b[k] = ab; tmp_n[k] = an;
        }
        __syncthreads();
        for (int k = 0; k < K; ++k) {
            group_basic[k*cube_vol + tz*bs*bs+ty*bs+tx] = tmp_b[k];
            group_noisy[k*cube_vol + tz*bs*bs+ty*bs+tx] = tmp_n[k];
        }
        __syncthreads();
    }

    // forward Haar across group axis, both buffers (already O(1) sync: per-e, k-loop inside)
    int haar_off = Haar_offset[31 - __clz(K)];
    int e = tz*bs*bs+ty*bs+tx;
    {
        float tmp_b[MAX_STACK], tmp_n[MAX_STACK];
        for (int i = 0; i < K; ++i) {
            float ab = 0.0f, an = 0.0f;
            for (int a = 0; a < K; ++a) {
                float h = Haar_flat[haar_off+i*K+a];
                ab += h*group_basic[a*cube_vol+e]; an += h*group_noisy[a*cube_vol+e];
            }
            tmp_b[i] = ab; tmp_n[i] = an;
        }
        for (int i = 0; i < K; ++i) { group_basic[i*cube_vol+e] = tmp_b[i]; group_noisy[i*cube_vol+e] = tmp_n[i]; }
    }
    __syncthreads();

    // Wiener shrinkage + omega-sum reduction (thread-local per e, no cross-thread
    // read/write hazard -- see note above about sum_omega2's summation order)
    if (tid == 0) s_sum_omega2 = 0.0f;
    __syncthreads();
    float sigma2 = sigma*sigma;
    float local_sum_omega2 = 0.0f;
    for (int k = 0; k < K; ++k) {
        int idx = k*cube_vol + e;
        float pb = group_basic[idx];
        float omega = (pb*pb) / (pb*pb + sigma2);
        local_sum_omega2 += omega*omega;
        group_noisy[idx] = omega*group_noisy[idx];
    }
    atomicAdd(&s_sum_omega2, local_sum_omega2);
    __syncthreads();
    // Bound the reciprocal: all-zero groups must not produce 0 * infinity.
    float weight = 1.0f / fmaxf(s_sum_omega2, 1e-12f);

    // inverse Haar, in place on group_noisy (group_basic no longer needed)
    {
        float tmp[MAX_STACK];
        for (int i = 0; i < K; ++i) {
            float acc = 0.0f;
            for (int a = 0; a < K; ++a) acc += Haar_flat[haar_off+a*K+i]*group_noisy[a*cube_vol+e];
            tmp[i] = acc;
        }
        for (int i = 0; i < K; ++i) group_noisy[i*cube_vol+e] = tmp[i];
    }
    __syncthreads();

    // inverse separable spatial transform, in place on group_noisy, O(1) syncs/pass
    {
        float tmp[MAX_STACK];
        for (int k = 0; k < K; ++k) {
            float acc = 0.0f; float* cube = group_noisy + k*cube_vol;
            for (int a = 0; a < bs; ++a) acc += T_spatial[a*bs+tz]*cube[a*bs*bs+ty*bs+tx];
            tmp[k] = acc;
        }
        __syncthreads();
        for (int k = 0; k < K; ++k) group_noisy[k*cube_vol + tz*bs*bs+ty*bs+tx] = tmp[k];
        __syncthreads();

        for (int k = 0; k < K; ++k) {
            float acc = 0.0f; float* cube = group_noisy + k*cube_vol;
            for (int b = 0; b < bs; ++b) acc += T_spatial[b*bs+ty]*cube[tz*bs*bs+b*bs+tx];
            tmp[k] = acc;
        }
        __syncthreads();
        for (int k = 0; k < K; ++k) group_noisy[k*cube_vol + tz*bs*bs+ty*bs+tx] = tmp[k];
        __syncthreads();

        for (int k = 0; k < K; ++k) {
            float acc = 0.0f; float* cube = group_noisy + k*cube_vol;
            for (int c = 0; c < bs; ++c) acc += T_spatial[c*bs+tx]*cube[tz*bs*bs+ty*bs+c];
            tmp[k] = acc;
        }
        __syncthreads();
        for (int k = 0; k < K; ++k) group_noisy[k*cube_vol + tz*bs*bs+ty*bs+tx] = tmp[k];
        __syncthreads();
    }

    float kw = Kaiser3d[e]*weight;
    for (int k = 0; k < K; ++k) {
        int cz = s_z[base+k], cy = s_y[base+k], cx = s_x[base+k];
        float val = group_noisy[k*cube_vol + e];
        atomicAdd(&numerator[(cz+tz)*ny*nx+(cy+ty)*nx+(cx+tx)], kw*val);
        atomicAdd(&denominator[(cz+tz)*ny*nx+(cy+ty)*nx+(cx+tx)], kw);
    }
}

__global__ void bm4d_wiener_f64_v3(
    const double* __restrict__ vol, const double* __restrict__ basic,
    double* __restrict__ numerator, double* __restrict__ denominator,
    const int nz, const int ny, const int nx,
    const int bs, const int search_r, const int max_stack,
    const double tau, const double sigma,
    const double* __restrict__ T_spatial, const double* __restrict__ Kaiser3d,
    const int* __restrict__ ref_z, const int* __restrict__ ref_y, const int* __restrict__ ref_x,
    const int n_refs,
    const double* __restrict__ Haar_flat, const int* __restrict__ Haar_offset,
    const int n_search
) {
    const int blk = blockIdx.x;
    if (blk >= n_refs) return;
    const int rz = ref_z[blk], ry = ref_y[blk], rx = ref_x[blk];

    const int tx = threadIdx.x, ty = threadIdx.y, tz = threadIdx.z;
    const int tid = tz*bs*bs + ty*bs + tx;
    const int cube_vol = bs*bs*bs;

    extern __shared__ double smem_wiener_f64[];
    __shared__ double s_dist[MAX_STACK];
    __shared__ int s_z[MAX_STACK], s_y[MAX_STACK], s_x[MAX_STACK];
    __shared__ int s_n, s_K;
    __shared__ double s_sum_omega2;

    double* stage_dist = smem_wiener_f64;
    int* stage_z = (int*)(stage_dist + n_search*max_stack);
    int* stage_y = stage_z + n_search*max_stack;
    int* stage_x = stage_y + n_search*max_stack;
    int* stage_n = stage_x + n_search*max_stack;
    int* stage_ntrue = stage_n + n_search;
    double* ref_cube = (double*)(stage_ntrue + n_search);

    ref_cube[tid] = basic[(rz+tz)*ny*nx + (ry+ty)*nx + (rx+tx)];
    __syncthreads();

    parallel_search_and_merge<double>(
        basic, ref_cube, nz, ny, nx, bs, cube_vol, rz, ry, rx, search_r, tau, max_stack,
        tid, n_search,
        stage_dist, stage_z, stage_y, stage_x, stage_n, stage_ntrue,
        s_dist, s_z, s_y, s_x, &s_n, &s_K
    );

    const int K = s_K;
    if (K == 0) return;
    const int base = s_n - K;

    double* group_basic = smem_wiener_f64;
    double* group_noisy = smem_wiener_f64 + (size_t)max_stack*cube_vol;

    for (int k = 0; k < K; ++k) {
        int cz = s_z[base+k], cy = s_y[base+k], cx = s_x[base+k];
        group_basic[k*cube_vol + tid] = basic[(cz+tz)*ny*nx + (cy+ty)*nx + (cx+tx)];
        group_noisy[k*cube_vol + tid] = vol[(cz+tz)*ny*nx + (cy+ty)*nx + (cx+tx)];
    }
    __syncthreads();

    {
        double tmp_b[MAX_STACK], tmp_n[MAX_STACK];
        for (int k = 0; k < K; ++k) {
            double ab = 0.0, an = 0.0;
            double* cb = group_basic + k*cube_vol; double* cn = group_noisy + k*cube_vol;
            for (int c = 0; c < bs; ++c) {
                double t = T_spatial[tx*bs+c];
                ab += t*cb[tz*bs*bs+ty*bs+c]; an += t*cn[tz*bs*bs+ty*bs+c];
            }
            tmp_b[k] = ab; tmp_n[k] = an;
        }
        __syncthreads();
        for (int k = 0; k < K; ++k) {
            group_basic[k*cube_vol + tz*bs*bs+ty*bs+tx] = tmp_b[k];
            group_noisy[k*cube_vol + tz*bs*bs+ty*bs+tx] = tmp_n[k];
        }
        __syncthreads();

        for (int k = 0; k < K; ++k) {
            double ab = 0.0, an = 0.0;
            double* cb = group_basic + k*cube_vol; double* cn = group_noisy + k*cube_vol;
            for (int b = 0; b < bs; ++b) {
                double t = T_spatial[ty*bs+b];
                ab += t*cb[tz*bs*bs+b*bs+tx]; an += t*cn[tz*bs*bs+b*bs+tx];
            }
            tmp_b[k] = ab; tmp_n[k] = an;
        }
        __syncthreads();
        for (int k = 0; k < K; ++k) {
            group_basic[k*cube_vol + tz*bs*bs+ty*bs+tx] = tmp_b[k];
            group_noisy[k*cube_vol + tz*bs*bs+ty*bs+tx] = tmp_n[k];
        }
        __syncthreads();

        for (int k = 0; k < K; ++k) {
            double ab = 0.0, an = 0.0;
            double* cb = group_basic + k*cube_vol; double* cn = group_noisy + k*cube_vol;
            for (int a = 0; a < bs; ++a) {
                double t = T_spatial[tz*bs+a];
                ab += t*cb[a*bs*bs+ty*bs+tx]; an += t*cn[a*bs*bs+ty*bs+tx];
            }
            tmp_b[k] = ab; tmp_n[k] = an;
        }
        __syncthreads();
        for (int k = 0; k < K; ++k) {
            group_basic[k*cube_vol + tz*bs*bs+ty*bs+tx] = tmp_b[k];
            group_noisy[k*cube_vol + tz*bs*bs+ty*bs+tx] = tmp_n[k];
        }
        __syncthreads();
    }

    int haar_off = Haar_offset[31 - __clz(K)];
    int e = tz*bs*bs+ty*bs+tx;
    {
        double tmp_b[MAX_STACK], tmp_n[MAX_STACK];
        for (int i = 0; i < K; ++i) {
            double ab = 0.0, an = 0.0;
            for (int a = 0; a < K; ++a) {
                double h = Haar_flat[haar_off+i*K+a];
                ab += h*group_basic[a*cube_vol+e]; an += h*group_noisy[a*cube_vol+e];
            }
            tmp_b[i] = ab; tmp_n[i] = an;
        }
        for (int i = 0; i < K; ++i) { group_basic[i*cube_vol+e] = tmp_b[i]; group_noisy[i*cube_vol+e] = tmp_n[i]; }
    }
    __syncthreads();

    if (tid == 0) s_sum_omega2 = 0.0;
    __syncthreads();
    double sigma2 = sigma*sigma;
    double local_sum_omega2 = 0.0;
    for (int k = 0; k < K; ++k) {
        int idx = k*cube_vol + e;
        double pb = group_basic[idx];
        double omega = (pb*pb) / (pb*pb + sigma2);
        local_sum_omega2 += omega*omega;
        group_noisy[idx] = omega*group_noisy[idx];
    }
    atomicAdd(&s_sum_omega2, local_sum_omega2);
    __syncthreads();
    double weight = 1.0 / fmax(s_sum_omega2, 1e-12);

    {
        double tmp[MAX_STACK];
        for (int i = 0; i < K; ++i) {
            double acc = 0.0;
            for (int a = 0; a < K; ++a) acc += Haar_flat[haar_off+a*K+i]*group_noisy[a*cube_vol+e];
            tmp[i] = acc;
        }
        for (int i = 0; i < K; ++i) group_noisy[i*cube_vol+e] = tmp[i];
    }
    __syncthreads();

    {
        double tmp[MAX_STACK];
        for (int k = 0; k < K; ++k) {
            double acc = 0.0; double* cube = group_noisy + k*cube_vol;
            for (int a = 0; a < bs; ++a) acc += T_spatial[a*bs+tz]*cube[a*bs*bs+ty*bs+tx];
            tmp[k] = acc;
        }
        __syncthreads();
        for (int k = 0; k < K; ++k) group_noisy[k*cube_vol + tz*bs*bs+ty*bs+tx] = tmp[k];
        __syncthreads();

        for (int k = 0; k < K; ++k) {
            double acc = 0.0; double* cube = group_noisy + k*cube_vol;
            for (int b = 0; b < bs; ++b) acc += T_spatial[b*bs+ty]*cube[tz*bs*bs+b*bs+tx];
            tmp[k] = acc;
        }
        __syncthreads();
        for (int k = 0; k < K; ++k) group_noisy[k*cube_vol + tz*bs*bs+ty*bs+tx] = tmp[k];
        __syncthreads();

        for (int k = 0; k < K; ++k) {
            double acc = 0.0; double* cube = group_noisy + k*cube_vol;
            for (int c = 0; c < bs; ++c) acc += T_spatial[c*bs+tx]*cube[tz*bs*bs+ty*bs+c];
            tmp[k] = acc;
        }
        __syncthreads();
        for (int k = 0; k < K; ++k) group_noisy[k*cube_vol + tz*bs*bs+ty*bs+tx] = tmp[k];
        __syncthreads();
    }

    double kw = Kaiser3d[e]*weight;
    for (int k = 0; k < K; ++k) {
        int cz = s_z[base+k], cy = s_y[base+k], cx = s_x[base+k];
        double val = group_noisy[k*cube_vol + e];
        atomicAdd(&numerator[(cz+tz)*ny*nx+(cy+ty)*nx+(cx+tx)], kw*val);
        atomicAdd(&denominator[(cz+tz)*ny*nx+(cy+ty)*nx+(cx+tx)], kw);
    }
}

// =========================================================================
// WIENER STAGE -- REVISION 1 FALLBACK (kept, unmodified from the previous
// version of this file). One thread per reference position, entirely
// in per-thread local memory, no __syncthreads() until the final
// atomicAdd scatter. This is used automatically -- see the Python
// launcher's _wiener_v3_search_width()/use_v3 logic -- ONLY when even a
// search width of 1 thread can't make Revision 3's shared-memory
// footprint fit this device's opt-in ceiling. In practice that means:
// float64, on any device whose ceiling is under ~64KB, because its two
// live 32*125-double group spectra (group_basic + group_noisy) are 64KB
// by themselves, BEFORE any search-staging memory is even counted --
// no search-width reduction can shrink that fixed cost, since it isn't
// part of the search-staging buffer this fallback logic can trade away.
// float32's spectra are half that (32KB), so it still fits Revision 3
// -- at a reduced, but still meaningfully parallel, search width -- on
// hardware that can't fit float64's. Run with bm4d(..., verbose=True)
// to see which path, and which search width, was actually selected on
// your GPU.
// =========================================================================
__global__ void bm4d_wiener_f32(
    const float* __restrict__ vol, const float* __restrict__ basic,
    float* __restrict__ numerator, float* __restrict__ denominator,
    const int nz, const int ny, const int nx,
    const int bs, const int search_r, const int max_stack,
    const float tau, const float sigma,
    const float* __restrict__ T_spatial, const float* __restrict__ Kaiser3d,
    const int* __restrict__ ref_z, const int* __restrict__ ref_y, const int* __restrict__ ref_x,
    const int n_refs,
    const float* __restrict__ Haar_flat, const int* __restrict__ Haar_offset
) {
    int idx = blockIdx.x * blockDim.x + threadIdx.x;
    if (idx >= n_refs) return;
    int rz = ref_z[idx], ry = ref_y[idx], rx = ref_x[idx];

    float stack_dist[MAX_STACK];
    int stack_z[MAX_STACK], stack_y[MAX_STACK], stack_x[MAX_STACK];
    int n = 0;

    int z0 = max(0, rz-search_r), z1 = min(nz-bs, rz+search_r);
    int y0 = max(0, ry-search_r), y1 = min(ny-bs, ry+search_r);
    int x0 = max(0, rx-search_r), x1 = min(nx-bs, rx+search_r);

    for (int cz = z0; cz <= z1; ++cz)
    for (int cy = y0; cy <= y1; ++cy)
    for (int cx = x0; cx <= x1; ++cx) {
        float ssd = 0.0f;
        for (int a = 0; a < bs; ++a)
        for (int b = 0; b < bs; ++b)
        for (int c = 0; c < bs; ++c) {
            float rv = basic[(rz+a)*ny*nx + (ry+b)*nx + (rx+c)];
            float cv = basic[(cz+a)*ny*nx + (cy+b)*nx + (cx+c)];
            float d = rv - cv;
            ssd += d * d;
        }
        float dist = ssd / (float)(bs*bs*bs);
        if (dist <= tau) add_stack<float>(stack_dist, stack_z, stack_y, stack_x, &n, dist, cz, cy, cx, max_stack);
    }

    int K = largest_pow2_leq(min(n, max_stack));
    int base = n - K;
    int cube_vol = bs*bs*bs;

    float group_basic[MAX_STACK * 125];
    float group_noisy[MAX_STACK * 125];
    float spec_basic[MAX_STACK * 125];
    float spec_noisy[MAX_STACK * 125];

    for (int k = 0; k < K; ++k) {
        int cz = stack_z[base+k], cy = stack_y[base+k], cx = stack_x[base+k];
        for (int e = 0; e < cube_vol; ++e) {
            int a = e/(bs*bs), b = (e/bs)%bs, c = e%bs;
            group_basic[k*cube_vol+e] = basic[(cz+a)*ny*nx + (cy+b)*nx + (cx+c)];
            group_noisy[k*cube_vol+e] = vol[(cz+a)*ny*nx + (cy+b)*nx + (cx+c)];
        }
    }

    for (int k = 0; k < K; ++k)
    for (int oe = 0; oe < cube_vol; ++oe) {
        int i = oe/(bs*bs), j = (oe/bs)%bs, l = oe%bs;
        float acc_b = 0.0f, acc_n = 0.0f;
        for (int a = 0; a < bs; ++a)
        for (int b = 0; b < bs; ++b)
        for (int c = 0; c < bs; ++c) {
            float w = T_spatial[i*bs+a]*T_spatial[j*bs+b]*T_spatial[l*bs+c];
            acc_b += w * group_basic[k*cube_vol + a*bs*bs+b*bs+c];
            acc_n += w * group_noisy[k*cube_vol + a*bs*bs+b*bs+c];
        }
        spec_basic[k*cube_vol+oe] = acc_b;
        spec_noisy[k*cube_vol+oe] = acc_n;
    }

    int haar_off = Haar_offset[31 - __clz(K)];
    for (int e = 0; e < cube_vol; ++e) {
        float tmp_b[MAX_STACK], tmp_n[MAX_STACK];
        for (int i = 0; i < K; ++i) {
            float acc_b = 0.0f, acc_n = 0.0f;
            for (int a = 0; a < K; ++a) {
                float h = Haar_flat[haar_off + i*K + a];
                acc_b += h * spec_basic[a*cube_vol+e];
                acc_n += h * spec_noisy[a*cube_vol+e];
            }
            tmp_b[i] = acc_b; tmp_n[i] = acc_n;
        }
        for (int i = 0; i < K; ++i) { group_basic[i*cube_vol+e] = tmp_b[i]; group_noisy[i*cube_vol+e] = tmp_n[i]; }
    }

    float sigma2 = sigma * sigma;
    float sum_omega2 = 0.0f;
    for (int e = 0; e < K*cube_vol; ++e) {
        float pb = group_basic[e];
        float omega = (pb*pb) / (pb*pb + sigma2);
        sum_omega2 += omega * omega;
        group_noisy[e] = omega * group_noisy[e];
    }
    float weight = 1.0f / fmaxf(sum_omega2, 1e-12f);

    for (int e = 0; e < cube_vol; ++e) {
        float tmp[MAX_STACK];
        for (int i = 0; i < K; ++i) {
            float acc = 0.0f;
            for (int a = 0; a < K; ++a) acc += Haar_flat[haar_off + a*K + i] * group_noisy[a*cube_vol+e];
            tmp[i] = acc;
        }
        for (int i = 0; i < K; ++i) spec_noisy[i*cube_vol+e] = tmp[i];
    }

    for (int k = 0; k < K; ++k)
    for (int oe = 0; oe < cube_vol; ++oe) {
        int a = oe/(bs*bs), b = (oe/bs)%bs, c = oe%bs;
        float acc = 0.0f;
        for (int i = 0; i < bs; ++i)
        for (int j = 0; j < bs; ++j)
        for (int l = 0; l < bs; ++l)
            acc += T_spatial[i*bs+a]*T_spatial[j*bs+b]*T_spatial[l*bs+c] * spec_noisy[k*cube_vol + i*bs*bs+j*bs+l];
        group_basic[k*cube_vol+oe] = acc;
    }

    for (int k = 0; k < K; ++k) {
        int cz = stack_z[base+k], cy = stack_y[base+k], cx = stack_x[base+k];
        for (int e = 0; e < cube_vol; ++e) {
            int a = e/(bs*bs), b = (e/bs)%bs, c = e%bs;
            float kw = Kaiser3d[e] * weight;
            atomicAdd(&numerator[(cz+a)*ny*nx + (cy+b)*nx + (cx+c)], kw * group_basic[k*cube_vol+e]);
            atomicAdd(&denominator[(cz+a)*ny*nx + (cy+b)*nx + (cx+c)], kw);
        }
    }
}

__global__ void bm4d_wiener_f64(
    const double* __restrict__ vol, const double* __restrict__ basic,
    double* __restrict__ numerator, double* __restrict__ denominator,
    const int nz, const int ny, const int nx,
    const int bs, const int search_r, const int max_stack,
    const double tau, const double sigma,
    const double* __restrict__ T_spatial, const double* __restrict__ Kaiser3d,
    const int* __restrict__ ref_z, const int* __restrict__ ref_y, const int* __restrict__ ref_x,
    const int n_refs,
    const double* __restrict__ Haar_flat, const int* __restrict__ Haar_offset
) {
    int idx = blockIdx.x * blockDim.x + threadIdx.x;
    if (idx >= n_refs) return;
    int rz = ref_z[idx], ry = ref_y[idx], rx = ref_x[idx];

    double stack_dist[MAX_STACK];
    int stack_z[MAX_STACK], stack_y[MAX_STACK], stack_x[MAX_STACK];
    int n = 0;

    int z0 = max(0, rz-search_r), z1 = min(nz-bs, rz+search_r);
    int y0 = max(0, ry-search_r), y1 = min(ny-bs, ry+search_r);
    int x0 = max(0, rx-search_r), x1 = min(nx-bs, rx+search_r);

    for (int cz = z0; cz <= z1; ++cz)
    for (int cy = y0; cy <= y1; ++cy)
    for (int cx = x0; cx <= x1; ++cx) {
        double ssd = 0.0;
        for (int a = 0; a < bs; ++a)
        for (int b = 0; b < bs; ++b)
        for (int c = 0; c < bs; ++c) {
            double rv = basic[(rz+a)*ny*nx + (ry+b)*nx + (rx+c)];
            double cv = basic[(cz+a)*ny*nx + (cy+b)*nx + (cx+c)];
            double d = rv - cv;
            ssd += d * d;
        }
        double dist = ssd / (double)(bs*bs*bs);
        if (dist <= tau) add_stack<double>(stack_dist, stack_z, stack_y, stack_x, &n, dist, cz, cy, cx, max_stack);
    }

    int K = largest_pow2_leq(min(n, max_stack));
    int base = n - K;
    int cube_vol = bs*bs*bs;

    double group_basic[MAX_STACK * 125];
    double group_noisy[MAX_STACK * 125];
    double spec_basic[MAX_STACK * 125];
    double spec_noisy[MAX_STACK * 125];

    for (int k = 0; k < K; ++k) {
        int cz = stack_z[base+k], cy = stack_y[base+k], cx = stack_x[base+k];
        for (int e = 0; e < cube_vol; ++e) {
            int a = e/(bs*bs), b = (e/bs)%bs, c = e%bs;
            group_basic[k*cube_vol+e] = basic[(cz+a)*ny*nx + (cy+b)*nx + (cx+c)];
            group_noisy[k*cube_vol+e] = vol[(cz+a)*ny*nx + (cy+b)*nx + (cx+c)];
        }
    }

    for (int k = 0; k < K; ++k)
    for (int oe = 0; oe < cube_vol; ++oe) {
        int i = oe/(bs*bs), j = (oe/bs)%bs, l = oe%bs;
        double acc_b = 0.0, acc_n = 0.0;
        for (int a = 0; a < bs; ++a)
        for (int b = 0; b < bs; ++b)
        for (int c = 0; c < bs; ++c) {
            double w = T_spatial[i*bs+a]*T_spatial[j*bs+b]*T_spatial[l*bs+c];
            acc_b += w * group_basic[k*cube_vol + a*bs*bs+b*bs+c];
            acc_n += w * group_noisy[k*cube_vol + a*bs*bs+b*bs+c];
        }
        spec_basic[k*cube_vol+oe] = acc_b;
        spec_noisy[k*cube_vol+oe] = acc_n;
    }

    int haar_off = Haar_offset[31 - __clz(K)];
    for (int e = 0; e < cube_vol; ++e) {
        double tmp_b[MAX_STACK], tmp_n[MAX_STACK];
        for (int i = 0; i < K; ++i) {
            double acc_b = 0.0, acc_n = 0.0;
            for (int a = 0; a < K; ++a) {
                double h = Haar_flat[haar_off + i*K + a];
                acc_b += h * spec_basic[a*cube_vol+e];
                acc_n += h * spec_noisy[a*cube_vol+e];
            }
            tmp_b[i] = acc_b; tmp_n[i] = acc_n;
        }
        for (int i = 0; i < K; ++i) { group_basic[i*cube_vol+e] = tmp_b[i]; group_noisy[i*cube_vol+e] = tmp_n[i]; }
    }

    double sigma2 = sigma * sigma;
    double sum_omega2 = 0.0;
    for (int e = 0; e < K*cube_vol; ++e) {
        double pb = group_basic[e];
        double omega = (pb*pb) / (pb*pb + sigma2);
        sum_omega2 += omega * omega;
        group_noisy[e] = omega * group_noisy[e];
    }
    double weight = 1.0 / fmax(sum_omega2, 1e-12);

    for (int e = 0; e < cube_vol; ++e) {
        double tmp[MAX_STACK];
        for (int i = 0; i < K; ++i) {
            double acc = 0.0;
            for (int a = 0; a < K; ++a) acc += Haar_flat[haar_off + a*K + i] * group_noisy[a*cube_vol+e];
            tmp[i] = acc;
        }
        for (int i = 0; i < K; ++i) spec_noisy[i*cube_vol+e] = tmp[i];
    }

    for (int k = 0; k < K; ++k)
    for (int oe = 0; oe < cube_vol; ++oe) {
        int a = oe/(bs*bs), b = (oe/bs)%bs, c = oe%bs;
        double acc = 0.0;
        for (int i = 0; i < bs; ++i)
        for (int j = 0; j < bs; ++j)
        for (int l = 0; l < bs; ++l)
            acc += T_spatial[i*bs+a]*T_spatial[j*bs+b]*T_spatial[l*bs+c] * spec_noisy[k*cube_vol + i*bs*bs+j*bs+l];
        group_basic[k*cube_vol+oe] = acc;
    }

    for (int k = 0; k < K; ++k) {
        int cz = stack_z[base+k], cy = stack_y[base+k], cx = stack_x[base+k];
        for (int e = 0; e < cube_vol; ++e) {
            int a = e/(bs*bs), b = (e/bs)%bs, c = e%bs;
            double kw = Kaiser3d[e] * weight;
            atomicAdd(&numerator[(cz+a)*ny*nx + (cy+b)*nx + (cx+c)], kw * group_basic[k*cube_vol+e]);
            atomicAdd(&denominator[(cz+a)*ny*nx + (cy+b)*nx + (cx+c)], kw);
        }
    }
}

__global__ void bm4d_divide_f32(
    const float* __restrict__ numerator, const float* __restrict__ denominator,
    const float* __restrict__ fallback, float* __restrict__ out, const int total
) {
    int i = blockIdx.x * blockDim.x + threadIdx.x;
    if (i >= total) return;
    float d = denominator[i];
    out[i] = (d != 0.0f) ? (numerator[i] / d) : fallback[i];
}

__global__ void bm4d_divide_f64(
    const double* __restrict__ numerator, const double* __restrict__ denominator,
    const double* __restrict__ fallback, double* __restrict__ out, const int total
) {
    int i = blockIdx.x * blockDim.x + threadIdx.x;
    if (i >= total) return;
    double d = denominator[i];
    out[i] = (d != 0.0) ? (numerator[i] / d) : fallback[i];
}

} /* extern "C" */
"""

_KERNELS = {}
def _get_kernel(name):
    if name not in _KERNELS:
        src = _CUDA_SOURCE.decode('ascii', errors='ignore')
        _KERNELS[name] = cp.RawKernel(src, name, options=('--std=c++11',))
    return _KERNELS[name]


# =========================================================================
# Small constant-array cache (Kaiser window, spatial transform matrix,
# Haar matrix bank)
# =========================================================================
# All three of these are pure functions of (bs and/or max_stack, dtype) --
# nothing about them depends on the volume being denoised. bm4d() used to
# rebuild each one on the host and re-upload it to the GPU on every call,
# which is pointless work for the common case of denoising many volumes
# with the same bs/max_stack profile (e.g. a batch loop). Caching them is
# a pure latency win with no numerical effect whatsoever: cache hits
# return the exact same device array that would otherwise have been
# rebuilt from the exact same host-side construction.
#
# Keys include the active device's id, not just (bs/max_stack, dtype) --
# unlike _get_kernel's RawKernel cache above (CuPy recompiles a RawKernel
# per-device internally, so one cached kernel object is safe to launch on
# any device), a cp.ndarray is physically resident on one specific
# device's memory. Keying on device id as well means this cache does the
# right thing automatically if the caller ever switches
# cp.cuda.Device(...) between bm4d() calls (multi-GPU workloads), rather
# than handing back a stale device's array.
_ARRAY_CACHE = {}

def _cached_array(key, build_fn):
    full_key = (cp.cuda.Device().id,) + key
    arr = _ARRAY_CACHE.get(full_key)
    if arr is None:
        arr = build_fn()
        _ARRAY_CACHE[full_key] = arr
    return arr


def _cached_kaiser(bs, dtype_np, dtype_tag):
    return _cached_array(
        ('kaiser', bs, dtype_tag),
        lambda: cp.asarray(_kaiser_3d(bs).astype(dtype_np))
    )


def _cached_bior15(dtype_np, dtype_tag):
    return _cached_array(
        ('bior15', dtype_tag),
        lambda: cp.asarray(_BIOR15_4.astype(dtype_np))
    )


def _cached_dct(bs, dtype_np, dtype_tag):
    return _cached_array(
        ('dct', bs, dtype_tag),
        # _dct_matrix ends with transpose and is F-contiguous. The CUDA
        # transform coefficients, just like volumes, require C indexing.
        lambda: cp.asarray(np.ascontiguousarray(_dct_matrix(bs), dtype=dtype_np))
    )


def _cached_haar_bank(max_stack, dtype_np, dtype_tag):
    def build():
        haar_flat, haar_off = _build_haar_bank(max_stack)
        return cp.asarray(haar_flat.astype(dtype_np)), cp.asarray(haar_off)
    return _cached_array(('haar', max_stack, dtype_tag), build)


# =========================================================================
# Shared-memory sizing + device capability (Revision 3)
# =========================================================================
# Every block-cooperative kernel here (HT, and Wiener's Revision 3 path)
# reuses the SAME dynamic shared-memory bytes for two different purposes
# at two different points in time: first as the parallel-search staging
# area (each thread's local top-max_stack candidate list, plus a small
# preloaded copy of the reference cube), then -- strictly after the
# __syncthreads() inside parallel_search_and_merge, by which point every
# read of that staging area has already happened -- as the group
# transform buffer(s). The bytes requested at launch time must therefore
# be the MAX of the two phases' requirements, computed identically here
# and in the kernels' own pointer arithmetic.
_STATIC_SMEM_MARGIN = 1024  # headroom for each kernel's small fixed __shared__
                            # scalars/arrays (s_dist/z/y/x, s_n, s_K, s_nret,
                            # s_sum_omega2) plus alignment padding -- these
                            # are NOT part of the dynamic buffer sized below,
                            # but count against the same per-block hardware
                            # limit, so capability checks reserve this much.

_DEVICE_SMEM_CACHE = {}
def _device_max_optin_smem():
    """This device's max shared memory per block available via the dynamic
    opt-in (cudaFuncAttributeMaxDynamicSharedMemorySize), in bytes. 49152
    (48 KB) on every CUDA GPU without opting in; higher (64 KB-227 KB
    depending on generation) if the device supports and we opt in."""
    dev_id = cp.cuda.Device().id
    if dev_id not in _DEVICE_SMEM_CACHE:
        try:
            val = int(cp.cuda.Device().attributes['MaxSharedMemoryPerBlockOptin'])
        except Exception:
            val = 49152
        _DEVICE_SMEM_CACHE[dev_id] = val
    return _DEVICE_SMEM_CACHE[dev_id]


def _configure_smem(kernel, nbytes):
    """Opt the kernel into >48KB dynamic shared memory if this call needs it."""
    if nbytes > 49152:
        kernel.max_dynamic_shared_size_bytes = int(nbytes)
    return nbytes


def _search_stage_bytes(n_search, cube_vol, max_stack, elem_bytes):
    """Bytes needed for the parallel-search staging area: n_search threads'
    worth of bounded candidate lists (dist + z + y + x) and counters
    (bounded count + true uncapped count), plus the preloaded reference
    cube (always cube_vol elements, loaded cooperatively by every voxel-
    owning thread regardless of how many threads do search work)."""
    n = n_search*max_stack*elem_bytes      # stage_dist
    n += n_search*max_stack*4*3            # stage_z, stage_y, stage_x (int32)
    n += n_search*4*2                      # stage_n, stage_ntrue (int32)
    n += cube_vol*elem_bytes               # ref_cube
    return n


def _ht_smem_bytes(bs, max_stack, elem_bytes):
    """HT searches with full per-voxel parallelism. bs_ht is fixed to 4;
    the caller checks the actual footprint against this GPU's limit."""
    cube_vol = bs**3
    phaseA = _search_stage_bytes(cube_vol, cube_vol, max_stack, elem_bytes)
    phaseB = max_stack*cube_vol*elem_bytes   # single `group` buffer
    return max(phaseA, phaseB)


def _wiener_v3_search_width(bs, max_stack, elem_bytes, device_max):
    """Find the widest search-worker thread count (n_search, <= bs^3) whose
    staging buffer fits alongside Wiener's group_basic+group_noisy transform
    buffers within this device's shared-memory budget, preferring full
    per-voxel parallelism (n_search == cube_vol) whenever there's room for
    it and otherwise shrinking ONLY the search width -- never max_stack,
    which would change denoising quality -- rounding down to a whole
    number of warps when that's not free, since a search width doesn't
    need to match cube_vol to stay exact (see parallel_search_and_merge's
    verification notes).

    Returns (n_search, smem_bytes), or (None, None) if the transform
    buffers alone don't fit at any search width -- meaning Revision 3 is
    not reachable on this device regardless of n_search, and the caller
    should fall back to Revision 1 entirely (this is the case for
    float64 on pre-Volta hardware: two 32*125-double spectra are 64KB by
    themselves, over Pascal's 48KB ceiling with nothing left to trade).
    """
    cube_vol = bs**3
    budget = device_max - _STATIC_SMEM_MARGIN
    phase_b = 2*max_stack*cube_vol*elem_bytes
    if phase_b > budget:
        return None, None

    per_thread = max_stack*(elem_bytes + 4*3) + 4*2   # bytes staged per search-worker thread
    fixed = cube_vol*elem_bytes                        # ref_cube, independent of n_search
    n_max = (budget - fixed) // per_thread
    n_max = max(1, min(cube_vol, n_max))
    if n_max < cube_vol and n_max >= 32:
        n_search = (n_max // 32) * 32   # round down to a whole number of warps
    else:
        n_search = n_max
    smem = max(_search_stage_bytes(n_search, cube_vol, max_stack, elem_bytes), phase_b)
    return n_search, smem


def bm4d(
    image,
    sigma,
    bs_ht=4, step_ht=3, max_stack_ht=16, search_ht=7, tau_ht=2.9527, lambda_thr=3.0,
    bs_wiener=5, step_wiener=3, max_stack_wiener=32, search_wiener=7, tau_wiener=0.7689,
    keep_on_gpu=False,
    verbose=False,
):
    """
    GPU-accelerated BM4D volumetric denoising (both stages). Default
    parameters match the 'np' 3-D profile of the reference bm4d package.

    Parameters
    ----------
    image : np.ndarray or cp.ndarray, shape (nz, ny, nx)
    sigma : float  Noise standard deviation (white/i.i.d. Gaussian).
    keep_on_gpu : bool  If True, return cp.ndarray instead of np.ndarray.
    verbose : bool  If True, print which Wiener kernel path (Revision 3
        block-cooperative, or the Revision 1 fallback) was selected for
        this device, and the shared-memory sizes involved. Off by default
        so normal usage stays quiet.

    Returns
    -------
    np.ndarray (or cp.ndarray), same shape as input.
    """
    if not isinstance(image, (np.ndarray, cp.ndarray)) or image.dtype.kind not in "fiu":
        raise TypeError("image must be a real numeric NumPy or CuPy array")
    validate_parameters(image.shape, sigma, bs_ht, step_ht, max_stack_ht, search_ht,
                        tau_ht, lambda_thr, bs_wiener, step_wiener, max_stack_wiener,
                        search_wiener, tau_wiener)
    use_f64 = image.dtype == np.float64
    dtype_np = np.float64 if use_f64 else np.float32
    dtype_tag = 'f64' if use_f64 else 'f32'
    elem_bytes = 8 if use_f64 else 4

    # All kernels use C-order pointer arithmetic. NIfTI is commonly F-order;
    # enforcing this in the core API also covers CuPy and strided views.
    vol = cp.ascontiguousarray(cp.asarray(image, dtype=dtype_np))
    if not bool(cp.isfinite(vol).all()):
        raise ValueError("BM4D core requires finite input; handle invalid FOV in the caller")

    nz, ny, nx = vol.shape
    sigma_c = dtype_np(sigma)
    if sigma == 0:
        return vol.copy() if keep_on_gpu else cp.asnumpy(vol)
    with np.errstate(over="ignore", under="ignore"):
        if not np.isfinite(sigma_c * sigma_c) or sigma_c * sigma_c == 0:
            raise ValueError("sigma squared is not representable in the selected precision")

    def run_ht(bs, step, max_stack, search_r, tau, lambda_thr):
        Kaiser = _cached_kaiser(bs, dtype_np, dtype_tag)
        T_gpu = _cached_bior15(dtype_np, dtype_tag)
        haar_flat, haar_off = _cached_haar_bank(max_stack, dtype_np, dtype_tag)

        zs, ys, xs = _ref_grid(nz, bs, step), _ref_grid(ny, bs, step), _ref_grid(nx, bs, step)
        rz, ry, rx = np.meshgrid(zs, ys, xs, indexing='ij')
        ref_z = cp.asarray(rz.ravel().astype(np.int32))
        ref_y = cp.asarray(ry.ravel().astype(np.int32))
        ref_x = cp.asarray(rx.ravel().astype(np.int32))
        n_refs = ref_z.size

        numerator = cp.zeros((nz, ny, nx), dtype=dtype_np)
        denominator = cp.zeros((nz, ny, nx), dtype=dtype_np)

        block = (bs, bs, bs)
        grid = (int(n_refs),)

        kernel_name = f'bm4d_ht_{dtype_tag}'
        smem = _ht_smem_bytes(bs, max_stack, elem_bytes)
        device_max = _device_max_optin_smem()
        if smem > device_max - _STATIC_SMEM_MARGIN:
            raise RuntimeError(
                f"HT stage needs {smem} bytes of dynamic shared memory per block "
                f"(bs_ht={bs}, max_stack_ht={max_stack}), but this GPU's per-block "
                f"opt-in maximum is {device_max} bytes. Reduce "
                f"max_stack_ht, or run on a GPU with more shared memory per SM."
            )

        kernel = _get_kernel(kernel_name)
        _configure_smem(kernel, smem)
        if verbose:
            print(f"[bm4d] HT stage: bm4d_ht_{dtype_tag}, shared_mem={smem} bytes "
                  f"(device opt-in max {device_max})")
        kernel(grid, block, (
            vol, numerator, denominator,
            np.int32(nz), np.int32(ny), np.int32(nx),
            np.int32(bs), np.int32(search_r), np.int32(max_stack),
            dtype_np(tau), dtype_np(lambda_thr), sigma_c,
            T_gpu, Kaiser, ref_z, ref_y, ref_x, np.int32(n_refs),
            haar_flat, haar_off,
        ), shared_mem=int(smem))
        cp.cuda.Stream.null.synchronize()

        out = cp.empty((nz, ny, nx), dtype=dtype_np)
        total = nz * ny * nx
        divide = _get_kernel(f'bm4d_divide_{dtype_tag}')
        # Tied block matches may leave a voxel without aggregation support;
        # retain its input instead of manufacturing a zero-valued boundary.
        divide(((total + 255) // 256,), (256,), (numerator, denominator, vol, out, np.int32(total)))
        cp.cuda.Stream.null.synchronize()
        return out

    def run_wiener(bs, step, max_stack, search_r, tau, basic_gpu):
        Kaiser = _cached_kaiser(bs, dtype_np, dtype_tag)
        T_gpu = _cached_dct(bs, dtype_np, dtype_tag)
        haar_flat, haar_off = _cached_haar_bank(max_stack, dtype_np, dtype_tag)

        zs, ys, xs = _ref_grid(nz, bs, step), _ref_grid(ny, bs, step), _ref_grid(nx, bs, step)
        rz, ry, rx = np.meshgrid(zs, ys, xs, indexing='ij')
        ref_z = cp.asarray(rz.ravel().astype(np.int32))
        ref_y = cp.asarray(ry.ravel().astype(np.int32))
        ref_x = cp.asarray(rx.ravel().astype(np.int32))
        n_refs = ref_z.size

        numerator = cp.zeros((nz, ny, nx), dtype=dtype_np)
        denominator = cp.zeros((nz, ny, nx), dtype=dtype_np)

        device_max = _device_max_optin_smem()
        n_search, smem_v3 = _wiener_v3_search_width(bs, max_stack, elem_bytes, device_max)
        use_v3 = n_search is not None

        if verbose:
            cube_vol = bs**3
            if use_v3:
                print(f"[bm4d] Wiener stage: Revision 3 (block-cooperative), "
                      f"n_search={n_search}/{cube_vol} threads, shared_mem={smem_v3} bytes "
                      f"(device opt-in max {device_max})")
            else:
                full_smem = _search_stage_bytes(cube_vol, cube_vol, max_stack, elem_bytes)
                phase_b = 2*max_stack*cube_vol*elem_bytes
                print(f"[bm4d] Wiener stage: Revision 1 (fallback, per-thread) -- transform "
                      f"buffers alone need {phase_b} bytes, device opt-in max is {device_max} "
                      f"bytes, no search width fits (full width would need {full_smem} bytes)")

        if use_v3:
            kernel = _get_kernel(f'bm4d_wiener_{dtype_tag}_v3')
            _configure_smem(kernel, smem_v3)
            block = (bs, bs, bs)
            grid = (int(n_refs),)
            kernel(grid, block, (
                vol, basic_gpu, numerator, denominator,
                np.int32(nz), np.int32(ny), np.int32(nx),
                np.int32(bs), np.int32(search_r), np.int32(max_stack),
                dtype_np(tau), sigma_c,
                T_gpu, Kaiser, ref_z, ref_y, ref_x, np.int32(n_refs),
                haar_flat, haar_off, np.int32(n_search),
            ), shared_mem=int(smem_v3))
        else:
            # Pre-Volta hardware (or anything whose opt-in ceiling can't fit
            # Revision 3's buffers): fall back to the original Revision 1
            # kernel -- one thread per reference position, fully local-memory,
            # no dynamic shared memory needed at all, so it always launches.
            kernel = _get_kernel(f'bm4d_wiener_{dtype_tag}')
            threads = 64
            grid = ((int(n_refs) + threads - 1) // threads,)
            block = (threads,)
            kernel(grid, block, (
                vol, basic_gpu, numerator, denominator,
                np.int32(nz), np.int32(ny), np.int32(nx),
                np.int32(bs), np.int32(search_r), np.int32(max_stack),
                dtype_np(tau), sigma_c,
                T_gpu, Kaiser, ref_z, ref_y, ref_x, np.int32(n_refs),
                haar_flat, haar_off,
            ))
        cp.cuda.Stream.null.synchronize()

        out = cp.empty((nz, ny, nx), dtype=dtype_np)
        total = nz * ny * nx
        divide = _get_kernel(f'bm4d_divide_{dtype_tag}')
        divide(((total + 255) // 256,), (256,), (numerator, denominator, basic_gpu, out, np.int32(total)))
        cp.cuda.Stream.null.synchronize()
        return out

    basic = run_ht(bs_ht, step_ht, max_stack_ht, search_ht, tau_ht, lambda_thr)
    if not bool(cp.isfinite(basic).all()):
        raise FloatingPointError("BM4D hard-thresholding stage produced NaN/Inf")
    final = run_wiener(bs_wiener, step_wiener, max_stack_wiener, search_wiener, tau_wiener, basic)
    if not bool(cp.isfinite(final).all()):
        raise FloatingPointError("BM4D Wiener stage produced NaN/Inf")

    if keep_on_gpu:
        return final
    return cp.asnumpy(final)
