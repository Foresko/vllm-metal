// SPDX-License-Identifier: Apache-2.0
// Flash-Attention-2 style paged attention kernel for Apple Silicon (BQ=32).
//
// Design points:
//
//   1. Q lives in registers for the entire KV loop (loaded ONCE).
//   2. O accumulator lives in registers (no per-tile O_smem round-trip).
//   3. Each simdgroup owns 8 complete Q rows (BQ=32 / NUM_SG=4 = 8).
//   4. Online softmax done entirely in registers via simd_shuffle_xor.
//   5. Mask applied to register S fragments (no S_smem round-trip).
//   6. 2 barriers per KV tile (K-load and V-load) instead of 4.
//
// The MMA fragment layout uses Apple's 8×8 simdgroup_matrix tile.  Each lane
// holds 2 elements of one fragment via thread_elements(); the (row, col) of
// those 2 elements is given by frag_coord() below — derived from MLX
// FlashAttention's MFAMMAFrag::get_coord (csrc/async_v2_kernel.metal:282).
//
// Paged-specific concerns vs. dense SDPA:
//   - K/V loaded with per-token block_tables[i/BLOCK_SIZE] lookup (cannot
//     use simdgroup_async_copy because each token may live in a different
//     physical block).  Cooperative threadgroup load instead.
//   - Varlen Q packing via cu_seqlens_q + binary search.
//   - Causal mask, sliding window, softcapping applied per-frag.
//
// Template: <T, HEAD_SIZE, BLOCK_SIZE, BQ=32, TILE_KV=32, NUM_THREADS=128>

// Requires utils.metal (DIVIDE_ROUND_UP, MIN, MAX), <metal_stdlib>, and
// `using namespace metal` from earlier in the source concat.

// ─────────────────────────────────────────────────────────────────────────
// Helper: thread → (row, col) inside an 8×8 simdgroup_matrix fragment.
// Element 0 of thread_elements() lives at (fm, fn).
// Element 1 of thread_elements() lives at (fm, fn+1).
// Verified against simdgroup_load+store round-trip.
//
// Per-lane ownership of the 8×8 fragment (Lk = lane k; each lane owns 2
// horizontally-adjacent cells of one row):
//
//          c0    c1    c2    c3    c4    c5    c6    c7
// row0 │   L0    L0    L1    L1    L8    L8    L9    L9
// row1 │   L2    L2    L3    L3    L10   L10   L11   L11
// row2 │   L4    L4    L5    L5    L12   L12   L13   L13
// row3 │   L6    L6    L7    L7    L14   L14   L15   L15
// row4 │   L16   L16   L17   L17   L24   L24   L25   L25
// row5 │   L18   L18   L19   L19   L26   L26   L27   L27
// row6 │   L20   L20   L21   L21   L28   L28   L29   L29
// row7 │   L22   L22   L23   L23   L30   L30   L31   L31
//
// Each row is split over exactly 4 lanes — e.g. row0 → {L0, L1, L8, L9}.
// Those 4 differ only in lane-id bits 0 and 3, which is exactly why the
// per-row softmax reduction below is simd_shuffle_xor with masks 1 then 8.
// ─────────────────────────────────────────────────────────────────────────
inline short2 frag_coord(ushort lane_id) {
  const short qid = short(lane_id) / 4;
  const short fm  = (qid & 4) + (short(lane_id) / 2) % 4;
  const short fn  = (qid & 2) * 2 + (short(lane_id) % 2) * 2;
  return short2{fn, fm};
}

// ─────────────────────────────────────────────────────────────────────────
// Reduce one row of the 8×8 fragment across the 4 lanes that share it.
//
// Masks {1, 8} are FORCED by the frag_coord layout above: the row index fm
// depends on lane bits {b4,b2,b1}, so the 4 lanes of a row vary only in
// bits {b0,b3} = XOR masks 1 and 8.  Two shuffles (log2(4)) reduce them,
// and because XOR-shuffle is a symmetric butterfly the result is replicated
// to all 4 lanes — the per-row online-softmax state below relies on that.
//
// Worked example — row 0 lives in lanes {0,1,8,9}; each lane starts with
// the max over its own 2 columns:
//
//             L0    L1    L8    L9
// start:       3     7     2     5            (true row max = 7; goal: all four = 7)
//
// step A:  x = max(x, simd_shuffle_xor(x, 1))      partner = lane ^ 1
//          L0↔L1   (0^1=1, 1^1=0)   L8↔L9  (8^1=9, 9^1=8)
//          L0 = max(3,7)=7   L1 = max(7,3)=7   L8 = max(2,5)=5   L9 = max(5,2)=5
//                  └── pair {0,1} now both 7 ──┘  └── pair {8,9} now both 5 ──┘
//
// step B:  x = max(x, simd_shuffle_xor(x, 8))      partner = lane ^ 8
//          L0↔L8   (0^8=8, 8^8=0)   L1↔L9  (1^8=9, 9^8=1)
//          L0 = max(7,5)=7   L8 = max(5,7)=7   L1 = max(7,5)=7   L9 = max(5,7)=7
//
// end:        7     7     7     7            ✓ every lane of the row holds the max
//
// Do NOT replace with simd_sum: all 8 rows of the fragment live in one
// 32-lane simdgroup, so a 32-lane reduction would fold the rows together.
//
// Op mirrors MLX Steel BaseMMAFrag<T,8,8>::row_reduce
// (mlx/backend/metal/kernels/steel/attn/mma.h) so this stays diff-able
// against upstream; vendored, not #included, to keep the Metal build off
// MLX's private steel header tree.
// ─────────────────────────────────────────────────────────────────────────
struct FragMax { static inline float apply(float a, float b) { return max(a, b); } };
struct FragSum { static inline float apply(float a, float b) { return a + b; } };

template <typename Op>
inline float frag_row_reduce(float v) {
  v = Op::apply(v, simd_shuffle_xor(v, ushort(1)));
  v = Op::apply(v, simd_shuffle_xor(v, ushort(8)));
  return v;
}

// Load unit for the cooperative K/V copy. Metal has no native vec<T,8>, so
// K/V bytes are bit-copied through uint2 (64-bit) / uint4 (128-bit) — native
// vectors that lower 1:1 to one wide load/store. A uint8_t[N] struct would
// rely on the optimizer to coalesce (and the zero-store could degrade to a
// memset loop). MLX steel BlockLoader pattern,
// mlx/backend/metal/kernels/steel/attn/loader.h.
template <int NBYTES> struct LoadUnit;
template <> struct LoadUnit<8>  { using type = uint2; };
template <> struct LoadUnit<16> { using type = uint4; };

// D_SPLIT: simdgroups per 8-row group.  With D_SPLIT > 1 the simdgroups of
// one row group all compute the same S = Q K^T (redundantly) and each owns
// HEAD_SIZE / D_SPLIT columns of O.  Q is then read from threadgroup memory
// per tile instead of being register-resident, so per-thread state shrinks to
// TD / D_SPLIT O fragments: the way HEAD_SIZE=512 fits registers and the
// 32 KB threadgroup budget with more than one simdgroup per threadgroup.
template <typename T, int HEAD_SIZE, int BLOCK_SIZE,
          int BQ = 32, int TILE_KV = 32, int NUM_THREADS = 128,
          int D_SPLIT = 1>
[[kernel]] void paged_attention_tiled(
    device T *out [[buffer(2)]],
    device const T *q [[buffer(3)]],
    device const T *k_cache [[buffer(4)]],
    device const T *v_cache [[buffer(5)]],
    const constant int &num_kv_heads [[buffer(8)]],
    const constant float &scale [[buffer(9)]],
    const constant float &softcapping [[buffer(10)]],
    device const uint32_t *block_tables [[buffer(11)]],
    device const uint32_t *context_lens [[buffer(12)]],
    const constant int &max_num_blocks_per_seq [[buffer(13)]],
    const constant int &q_stride [[buffer(15)]],
    const constant int &kv_block_stride [[buffer(16)]],
    const constant int &kv_head_stride [[buffer(17)]],
    device const float *sinks
    [[buffer(18), function_constant(use_sinks)]],
    device const int32_t *cu_seqlens_q [[buffer(19)]],
    const constant int &num_seqs [[buffer(20)]],
    const constant int &sliding_window [[buffer(21)]],
    device const int32_t *mm_prefix_ranges
    [[buffer(22), function_constant(use_mm_prefix)]],
    threadgroup char *shared_mem [[threadgroup(0)]],
    uint3 tgp [[threadgroup_position_in_grid]],
    uint3 tgpg [[threadgroups_per_grid]],
    uint3 tpt [[thread_position_in_threadgroup]],
    uint sg_idx [[simdgroup_index_in_threadgroup]],
    uint lane [[thread_index_in_simdgroup]])
{
  constexpr int NUM_SIMD_LANES = 32;
  constexpr int NUM_SG = NUM_THREADS / NUM_SIMD_LANES;
  constexpr int TD = HEAD_SIZE / 8;        // # of 8-wide D fragments
  constexpr int TK = TILE_KV / 8;          // # of 8-wide K fragments
  constexpr int ROW_SGS = NUM_SG / D_SPLIT;  // simdgroup row groups
  constexpr int ROWS_PER_SG = BQ / ROW_SGS;   // 8 rows per row group
  constexpr int TD_O = TD / D_SPLIT;         // O fragments per simdgroup

  static_assert(HEAD_SIZE % 8 == 0, "HEAD_SIZE must be a multiple of 8");
  static_assert(TILE_KV % 8 == 0, "TILE_KV must be a multiple of 8");
  static_assert(BQ % NUM_SG == 0, "BQ must be divisible by NUM_SG");
  static_assert(ROWS_PER_SG == 8, "ROWS_PER_SG must equal 8 (frag rows)");
  static_assert(NUM_SG % D_SPLIT == 0, "D_SPLIT must divide NUM_SG");
  static_assert(TD % D_SPLIT == 0, "D_SPLIT must divide the fragment count");
  static_assert(TILE_KV % NUM_SG == 0, "K/V rows split evenly across simdgroups");

  const int thread_idx = tpt.x;
  const int head_idx = tgp.x;
  // Row group and O column part of this simdgroup (D_SPLIT == 1: identity).
  const int row_sg = int(sg_idx) / D_SPLIT;
  const int d_part = int(sg_idx) % D_SPLIT;
  const int d_base = d_part * TD_O;  // first O fragment this simdgroup owns
  const int q_block_global_idx = tgp.y;
  const int num_heads = tgpg.x;
  const int num_queries_per_kv = num_heads / num_kv_heads;
  const int kv_head_idx = head_idx / num_queries_per_kv;
  const int kv_token_stride = num_kv_heads * kv_head_stride;

  // ─ Varlen: resolve sequence and Q-block position (binary search) ──────
  int seq_idx;
  {
    int lo = 0, hi = num_seqs;
    while (lo < hi) {
      int mid = (lo + hi + 1) / 2;
      if (cu_seqlens_q[mid] / BQ + mid <= q_block_global_idx) lo = mid;
      else hi = mid - 1;
    }
    seq_idx = lo;
  }

  const int q_seq_start = cu_seqlens_q[seq_idx];
  const int cur_batch_query_len = cu_seqlens_q[seq_idx + 1] - q_seq_start;
  const int q_block_start = q_seq_start / BQ + seq_idx;
  const int q_block_local = q_block_global_idx - q_block_start;
  const int q_pos_start = q_block_local * BQ;

  if (q_pos_start >= cur_batch_query_len) return;

  const int seq_len = int(context_lens[seq_idx]);
  const int context_len = seq_len - cur_batch_query_len;
  const int valid_q = min(BQ, cur_batch_query_len - q_pos_start);

  // ─ Threadgroup memory layout (A1: bank-conflict padding) ──────────────
  // Each row padded to LD = HEAD_SIZE + SMEM_PAD so the 8 columns of every
  // 8×8 simdgroup_load/store land on distinct threadgroup-memory banks
  // (a HEAD_SIZE power-of-two stride aliases them).  The fp32 O_smem that
  // aliases Q_smem at exit reuses the SAME LD.
  //   Q_smem: BQ × LD,   K_smem/V_smem: TILE_KV × LD.
  constexpr int SMEM_PAD = 16 / sizeof(T);   // 8 elems (16 B) for fp16/bf16
  constexpr int LD = HEAD_SIZE + SMEM_PAD;   // padded leading dim
  constexpr int Q_ELEMS = BQ * LD;
  constexpr int KV_ELEMS = TILE_KV * LD;

  threadgroup T *Q_smem = reinterpret_cast<threadgroup T *>(shared_mem);
  threadgroup T *K_smem = Q_smem + Q_ELEMS;
  threadgroup T *V_smem = K_smem + KV_ELEMS;
  // D_SPLIT > 1: each simdgroup computes S over its own HEAD_SIZE / D_SPLIT
  // columns of Q and K; the partial 8×8 S fragments are exchanged here and
  // summed by every simdgroup of the row group.  [ROW_SGS][D_SPLIT][TK] frags
  // of 64 floats.  Unused (zero-sized on the host side) when D_SPLIT == 1.
  threadgroup float *S_xchg =
      reinterpret_cast<threadgroup float *>(V_smem + KV_ELEMS);

  const float scale_log2 = scale * M_LOG2E_F;

  // ─ Load Q into Q_smem [BQ, HEAD_SIZE] (cooperative) ───────────────────
  // Rows with row >= valid_q get zero-Q (their S values will be masked
  // anyway, but zeroing avoids garbage propagating through QK).
  const device T *q_base = q + (q_seq_start + q_pos_start) * q_stride
                             + head_idx * HEAD_SIZE;
  for (int i = thread_idx; i < BQ * HEAD_SIZE; i += NUM_THREADS) {
    int r = i / HEAD_SIZE;
    int d = i % HEAD_SIZE;
    Q_smem[r * LD + d] = (r < valid_q) ? q_base[r * q_stride + d] : T(0);
  }

  threadgroup_barrier(mem_flags::mem_threadgroup);

  // ─ Load Q into register fragments (once, reused across all KV tiles) ──
  // Each simdgroup owns 8 contiguous rows: [sg_idx*8, sg_idx*8 + 8).
  // For each fragment, we load Q_smem[sg_idx*8..sg_idx*8+8, d*8..d*8+8].
  //
  // We use vec<T,2> arrays (MLX MFAMMAFrag pattern) for register storage.
  // simdgroup_matrix instances are materialized only at the MMA call site —
  // this gives the compiler an unambiguous signal that the data lives in
  // per-thread registers, not in some implicit threadgroup memory.
  using vec2T = vec<T, 2>;
  using vec2F = vec<float, 2>;
  // With D_SPLIT > 1 the Q fragments are re-read from Q_smem on every tile
  // (Q_smem stays intact until the output staging after the loop); the
  // register array is then unused and elided.
  constexpr int QREG_N = (D_SPLIT == 1) ? TD : 1;
  vec2T Qreg[QREG_N];
  if (D_SPLIT == 1) {
    #pragma unroll
    for (int d = 0; d < TD; d++) {
      simdgroup_matrix<T, 8, 8> tmp;
      simdgroup_load(tmp, Q_smem + row_sg * 8 * LD + d * 8, LD);
      Qreg[d] = reinterpret_cast<thread vec2T &>(tmp.thread_elements());
    }
  }

  // ─ Initialize per-simdgroup-row online softmax state ──────────────────
  // Each thread tracks max/sum for the row it owns inside the 8×8 frag.
  // Lane → (fm, fn) — fm is the row this thread contributes to.
  const short2 fc = frag_coord(ushort(lane));
  const short fm = fc.y;   // row within the 8-row tile owned by this SG
  const short fn = fc.x;   // col within the 8-col fragment

  // Per-thread accumulator state — broadcast across lanes that share fm.
  float max_score = -INFINITY;
  float sum_score = 0.0f;

  // O accumulator: TD fragments of (8 × 8) per simdgroup, register-resident.
  // Each lane holds vec<float,2> per fragment.
  vec2F Oreg[TD_O];
  #pragma unroll
  for (int d = 0; d < TD_O; d++) {
    Oreg[d] = vec2F(0.0f);
  }

  const device uint32_t *block_table =
      block_tables + seq_idx * max_num_blocks_per_seq;
  const int num_kv_tiles = DIVIDE_ROUND_UP(seq_len, TILE_KV);

  // Row ownership is fixed for the whole tile loop: rows >= valid_q are
  // padding, never read the range buffer and stay masked.
  const bool row_masked = (row_sg * 8 + fm) >= valid_q;

  // ─ mm_prefix (Gemma 4 vision) ─────────────────────────────────────────
  // [r_start, r_end]: inclusive absolute key positions of this row's image
  // block, (-1, -1) for text rows (in_block is then never true).  tile_stop
  // is the threadgroup's causal frontier extended to the furthest block end
  // among its rows, so the tile loop still visits block keys that lie right
  // of the frontier.  valid_q is threadgroup-uniform, so every thread
  // computes the same tile_stop without a barrier; the redundant BQ loads
  // per thread are what the phase-3 A/B measures.
  int r_start = -1;
  int r_end = -1;
  int tile_stop = context_len + q_pos_start + valid_q - 1;
  if (use_mm_prefix) {
    const int q_row_base = q_seq_start + q_pos_start;
    if (!row_masked) {
      const int q_row = q_row_base + row_sg * 8 + fm;
      r_start = mm_prefix_ranges[2 * q_row];
      r_end = mm_prefix_ranges[2 * q_row + 1];
    }
    for (int r = 0; r < valid_q; r++) {
      tile_stop = max(tile_stop, mm_prefix_ranges[2 * (q_row_base + r) + 1]);
    }
  }

  // Sliding window: every key left of the earliest row's window is masked
  // for every row of this threadgroup, so those tiles contribute nothing
  // and the loop starts at the first tile that can hold an attended key
  // (the NAX kernel bounds its loop the same way).  Without this the 25
  // sliding layers of Gemma 4 visited every tile of a 32K prompt and cost as
  // much as full attention.  context_len and q_pos_start are uniform, so
  // the bound needs no barrier; rows >= valid_q stay masked regardless.
  const int tg_min_q_abs_pos = context_len + q_pos_start;
  const int tg_max_q_abs_pos = tg_min_q_abs_pos + valid_q - 1;
  int tile_idx_start = 0;
  if (sliding_window >= 0) {
    tile_idx_start = max(0, (tg_min_q_abs_pos + 1 - sliding_window) / TILE_KV);
  }

  // ─ MAIN KV TILE LOOP ──────────────────────────────────────────────────
  for (int tile_idx = tile_idx_start; tile_idx < num_kv_tiles; tile_idx++) {
    const int tile_start = tile_idx * TILE_KV;

    // Causal skip: stop once the whole tile lies beyond every key this
    // threadgroup can attend (the causal frontier, or the furthest image
    // block end when mm_prefix is on).  num_kv_tiles still bounds the loop.
    if (tile_start > tile_stop) break;

    // ─ Load K AND V cooperatively (paged, fused, wide-vectorized) ────
    // Both K_smem and V_smem are filled in the same loop:
    //   * block_table lookup is shared (same kv_pos for both K and V)
    //   * memory controller interleaves K and V reads from the same
    //     physical block, hiding K-load latency behind V-load and v.v.
    //   * saves a barrier vs loading them separately
    //
    // Cooperative K/V load width scales with HEAD_SIZE: 128-bit (16 B)
    // transactions for HEAD_SIZE >= 256 (Gemma 4's 256/512), 64-bit (8 B)
    // for <= 128.  Metal has no native vec<T,8>, so the 16 B path needs
    // the LoadUnit byte-struct + reinterpret pattern; the 8 B path could
    // equivalently be vec<T,4>, but we route both through LoadUnit for
    // uniformity.
    //
    // Strided layout preserved (lane owns d=lane*VEC, stride NUM_SIMD_LANES
    // *VEC): consecutive lanes touch consecutive VEC-element runs -> reads
    // stay coalesced, and all 32 lanes stay active at 256/512.
    //
    // Alignment (verified for HEAD_SIZE in {64,96,128,256,512}): device
    // `off` is a multiple of HEAD_SIZE elems; smem stride LD=HEAD_SIZE+8;
    // both make `&[t*LD + lane*VEC]` a multiple of VEC_BYTES.
    constexpr int VEC_BYTES = (HEAD_SIZE >= 256) ? 16 : 8;
    constexpr int VEC = VEC_BYTES / int(sizeof(T));
    using vecLoadT = typename LoadUnit<VEC_BYTES>::type;  // uint2 / uint4
    // Guards the alignment claimed above: LD%VEC==0 keeps every
    // &K_smem[t*LD + lane*VEC] a multiple of VEC_BYTES (device side is
    // aligned via `off`, a multiple of HEAD_SIZE).
    static_assert(LD % VEC == 0, "smem row stride LD must be VEC-aligned");
    #pragma unroll
    for (int t_iter = 0; t_iter < TILE_KV / NUM_SG; t_iter++) {
      int t = sg_idx * (TILE_KV / NUM_SG) + t_iter;
      int kv_pos = tile_start + t;
      if (kv_pos < seq_len) {
        int64_t pb = int64_t(block_table[kv_pos / BLOCK_SIZE]);
        const int64_t off = pb * kv_block_stride
            + (kv_pos % BLOCK_SIZE) * kv_token_stride
            + kv_head_idx * kv_head_stride;
        const device T *k_ptr = k_cache + off;
        const device T *v_ptr = v_cache + off;
        #pragma unroll
        for (int d = lane * VEC; d < HEAD_SIZE; d += NUM_SIMD_LANES * VEC) {
          *((threadgroup vecLoadT *)&K_smem[t * LD + d]) =
              *((const device vecLoadT *)(k_ptr + d));
          *((threadgroup vecLoadT *)&V_smem[t * LD + d]) =
              *((const device vecLoadT *)(v_ptr + d));
        }
      } else {
        const vecLoadT zero = {};  // all-zero bits == +0.0 in half/bf16
        #pragma unroll
        for (int d = lane * VEC; d < HEAD_SIZE; d += NUM_SIMD_LANES * VEC) {
          *((threadgroup vecLoadT *)&K_smem[t * LD + d]) = zero;
          *((threadgroup vecLoadT *)&V_smem[t * LD + d]) = zero;
        }
      }
    }

    threadgroup_barrier(mem_flags::mem_threadgroup);  // K & V visible

    // ─ QK matmul: S[8, TILE_KV] = Q × K^T via 8×8 MMA ──────────────────
    // Q is in registers (Qreg); K is read from shared memory with transpose.
    // Each simdgroup computes the 8 rows it owns × all TILE_KV cols.
    // S accumulator (Sreg) is float-vec<2> per lane per K-frag.
    vec2F Sreg[TK];
    #pragma unroll
    for (int k = 0; k < TK; k++) {
      Sreg[k] = vec2F(0.0f);
    }

    // Each simdgroup covers only its own column part of the head dimension
    // (all of it when D_SPLIT == 1); the parts are summed below.
    #pragma unroll
    for (int dd = 0; dd < TD_O; dd++) {
      const int d = d_base + dd;
      // Materialize Q fragment: from registers (D_SPLIT == 1) or from
      // threadgroup memory (D_SPLIT > 1, one 8×8 load per fragment).
      simdgroup_matrix<T, 8, 8> q_frag;
      if (D_SPLIT == 1) {
        reinterpret_cast<thread vec2T &>(q_frag.thread_elements()) =
            Qreg[(D_SPLIT == 1) ? d : 0];
      } else {
        simdgroup_load(q_frag, Q_smem + row_sg * 8 * LD + d * 8, LD);
      }

      #pragma unroll
      for (int k = 0; k < TK; k++) {
        simdgroup_matrix<T, 8, 8> k_frag;
        simdgroup_load(k_frag,
                       K_smem + k * 8 * LD + d * 8,
                       LD, ulong2(0), /*transpose=*/true);

        // Materialize S accumulator from register vec → simdgroup_matrix.
        simdgroup_matrix<float, 8, 8> s_frag;
        reinterpret_cast<thread vec2F &>(s_frag.thread_elements()) = Sreg[k];

        simdgroup_multiply_accumulate(s_frag, q_frag, k_frag, s_frag);

        // Pull result back into register vec.
        Sreg[k] = reinterpret_cast<thread vec2F &>(s_frag.thread_elements());
      }
    }

    // ─ D_SPLIT > 1: sum the partial S fragments across the row group ──
    if (D_SPLIT > 1) {
      #pragma unroll
      for (int k = 0; k < TK; k++) {
        simdgroup_matrix<float, 8, 8> part;
        reinterpret_cast<thread vec2F &>(part.thread_elements()) = Sreg[k];
        simdgroup_store(part,
                        S_xchg + ((row_sg * D_SPLIT + d_part) * TK + k) * 64,
                        8);
      }
      threadgroup_barrier(mem_flags::mem_threadgroup);
      #pragma unroll
      for (int k = 0; k < TK; k++) {
        vec2F acc = vec2F(0.0f);
        #pragma unroll
        for (int p = 0; p < D_SPLIT; p++) {
          simdgroup_matrix<float, 8, 8> part;
          simdgroup_load(part,
                         S_xchg + ((row_sg * D_SPLIT + p) * TK + k) * 64,
                         8);
          acc += reinterpret_cast<thread vec2F &>(part.thread_elements());
        }
        Sreg[k] = acc;
      }
      // The next tile's partial-S stores happen after this iteration's
      // closing barrier, so no further barrier is needed here.
    }

    // ─ Scale + apply mask + softcap (all in registers) ─────────────────
    // Fast path: when the entire tile is "before" the causal frontier of
    // every Q row in this threadgroup, no causal/padding mask is needed.
    // This applies to most tiles in long-prefill (tile_start + TILE_KV - 1
    // < min_q_abs_pos in this threadgroup; min_q_abs_pos = context_len +
    // q_pos_start).  Saves ~16 ALU ops per element on tiles 0..N_safe-1.
    // With a sliding window the tile is also unmasked when it lies inside
    // the window of the *last* row of the threadgroup (the tightest one):
    // then every row's window covers the whole tile.
    const int q_abs_pos = tg_min_q_abs_pos + row_sg * 8 + fm;
    const int min_q_abs_pos = tg_min_q_abs_pos;
    const bool tile_no_mask = (tile_start + TILE_KV - 1) < min_q_abs_pos
                              && (tile_start + TILE_KV) <= seq_len
                              && softcapping <= 0.0f
                              && (sliding_window < 0
                                  || tile_start >= tg_max_q_abs_pos + 1 - sliding_window);

    if (tile_no_mask && !row_masked) {
      #pragma unroll
      for (int k = 0; k < TK; k++) {
        Sreg[k][0] *= scale_log2;
        Sreg[k][1] *= scale_log2;
      }
    } else {
      #pragma unroll
      for (int k = 0; k < TK; k++) {
        #pragma unroll
        for (int jj = 0; jj < 2; jj++) {
          float s = Sreg[k][jj] * scale_log2;
          if (softcapping > 0.0f) {
            float s_orig = s / M_LOG2E_F;
            s = softcapping * precise::tanh(s_orig / softcapping) * M_LOG2E_F;
          }
          int kv_pos = tile_start + k * 8 + fn + jj;
          // (causal OR same image block) AND window: HF Gemma 4 semantics.
          // in_block folds to false when use_mm_prefix is off, and it can
          // never open a key at or beyond seq_len.
          const bool in_block = use_mm_prefix
                                && (kv_pos >= r_start) && (kv_pos <= r_end);
          bool masked = row_masked
                        || ((kv_pos > q_abs_pos) && !in_block)
                        || (kv_pos >= seq_len);
          if (sliding_window >= 0)
            masked = masked || (kv_pos < q_abs_pos + 1 - sliding_window);
          Sreg[k][jj] = masked ? -INFINITY : s;
        }
      }
    }

    // ─ Row max: local max across 2*TK elements, then XOR-reduce ─────────
    float local_max = -INFINITY;
    #pragma unroll
    for (int k = 0; k < TK; k++) {
      local_max = max(local_max, max(Sreg[k][0], Sreg[k][1]));
    }
    float row_max = frag_row_reduce<FragMax>(local_max);

    float new_max = max(max_score, row_max);
    float factor;
    if (new_max > max_score) {
      factor = (max_score == -INFINITY) ? 0.0f
                                        : fast::exp2(max_score - new_max);
    } else {
      factor = 1.0f;
      if (max_score == -INFINITY) new_max = 0.0f;
    }
    max_score = new_max;

    // ─ Exponentiate + row sum ───────────────────────────────────────────
    float local_sum = 0.0f;
    #pragma unroll
    for (int k = 0; k < TK; k++) {
      #pragma unroll
      for (int jj = 0; jj < 2; jj++) {
        float p = (Sreg[k][jj] == -INFINITY)
                      ? 0.0f
                      : fast::exp2(Sreg[k][jj] - new_max);
        Sreg[k][jj] = p;
        local_sum += p;
      }
    }
    float row_sum = frag_row_reduce<FragSum>(local_sum);

    sum_score = sum_score * factor + row_sum;

    // ─ Rescale O in registers ───────────────────────────────────────────
    #pragma unroll
    for (int d = 0; d < TD_O; d++) {
      Oreg[d] *= factor;
    }

    // ─ PV matmul: O += P × V via 8×8 MMA ───────────────────────────────
    // V was loaded above together with K — no additional barrier needed.
    // (One barrier at the END of this iteration protects V_smem against
    //  the next iteration's K+V load.)
    // P is in registers (Sreg, fp32). V is in smem. O accumulator stays in
    // registers (Oreg).  P is kept fp32 into the MMA (mixed float×T→float),
    // matching the pre-PR kernel exactly — this PR is precision-neutral.
    // Sreg is already vec2F, so this is the same MFAMMAFrag reinterpret used
    // for Q/S/O (no downcast).  Narrowing P to T is a separate,
    // benchmark-gated follow-up, not bundled into this perf migration.
    #pragma unroll
    for (int k = 0; k < TK; k++) {
      simdgroup_matrix<float, 8, 8> p_frag;
      reinterpret_cast<thread vec2F &>(p_frag.thread_elements()) = Sreg[k];

      #pragma unroll
      for (int d = 0; d < TD_O; d++) {
        simdgroup_matrix<T, 8, 8> v_frag;
        simdgroup_load(v_frag,
                       V_smem + k * 8 * LD + (d_base + d) * 8,
                       LD);

        // Materialize O accumulator fragment from register vec.
        simdgroup_matrix<float, 8, 8> o_frag;
        reinterpret_cast<thread vec2F &>(o_frag.thread_elements()) = Oreg[d];

        simdgroup_multiply_accumulate(o_frag, p_frag, v_frag, o_frag);

        Oreg[d] = reinterpret_cast<thread vec2F &>(o_frag.thread_elements());
      }
    }

    // Protect V_smem against the next iteration's K+V load.  PV above
    // reads ALL rows of V_smem; the next iteration's load writes V_smem.
    // Without this barrier, fast simdgroups can corrupt slow ones' reads.
    threadgroup_barrier(mem_flags::mem_threadgroup);
  } // end KV tile loop

  // Fold the attention sink into each valid row's online-softmax state once.
  // It contributes one learned logit to the denominator and no value row, so
  // O is only rescaled by the max correction.
  if (use_sinks && (row_sg * 8 + fm) < valid_q) {
    const float sink_score = sinks[head_idx] * M_LOG2E_F;
    const float new_max = max(max_score, sink_score);
    const float old_corr =
        (max_score == -INFINITY) ? 0.0f : fast::exp2(max_score - new_max);
    const float sink_exp = fast::exp2(sink_score - new_max);
    sum_score = sum_score * old_corr + sink_exp;
    max_score = new_max;
    #pragma unroll
    for (int d = 0; d < TD_O; d++) {
      Oreg[d] *= old_corr;
    }
  }

  // ─ Final normalize: O /= sum_score, then store ────────────────────────
  // sum_score is broadcast-replicated across lanes with same fm.
  float inv_sum = 1.0f / (sum_score + 1e-6f);
  #pragma unroll
  for (int d = 0; d < TD_O; d++) {
    Oreg[d] *= inv_sum;
  }

  // Reuse Q_smem as the output staging buffer (it's no longer needed).
  // Each simdgroup stores its 8 rows × HEAD_SIZE into Q_smem (as float).
  // With D_SPLIT > 1 the row group's simdgroups each store their own
  // column part; every simdgroup passed the loop's final barrier, so no
  // Q_smem read is still in flight.
  threadgroup float *O_smem = reinterpret_cast<threadgroup float *>(Q_smem);
  #pragma unroll
  for (int d = 0; d < TD_O; d++) {
    simdgroup_matrix<float, 8, 8> o_frag;
    reinterpret_cast<thread vec2F &>(o_frag.thread_elements()) = Oreg[d];
    simdgroup_store(o_frag,
                    O_smem + row_sg * 8 * LD + (d_base + d) * 8,
                    LD);
  }

  threadgroup_barrier(mem_flags::mem_threadgroup);

  // Write to global memory, respecting valid_q.
  device T *out_base = out + (q_seq_start + q_pos_start) * q_stride
                           + head_idx * HEAD_SIZE;
  const int total = valid_q * HEAD_SIZE;
  for (int i = thread_idx; i < total; i += NUM_THREADS) {
    int r = i / HEAD_SIZE;
    int d = i % HEAD_SIZE;
    out_base[r * q_stride + d] = T(O_smem[r * LD + d]);
  }
}

// ─── Template instantiation ──────────────────────────────────────────────

#define instantiate_paged_attention_tiled_inner(type, head_size, block_size,   \
                                                bq, tkv, nt, ds)               \
  template [[host_name("paged_attention_tiled_" #type                          \
                       "_hs" #head_size "_bs" #block_size                      \
                       "_bq" #bq "_tk" #tkv "_nt" #nt "_ds" #ds)]]             \
  [[kernel]] void paged_attention_tiled<type, head_size, block_size,           \
                                        bq, tkv, nt, ds>(                      \
      device type *out [[buffer(2)]],                                          \
      device const type *q [[buffer(3)]],                                      \
      device const type *k_cache [[buffer(4)]],                                \
      device const type *v_cache [[buffer(5)]],                                \
      const constant int &num_kv_heads [[buffer(8)]],                          \
      const constant float &scale [[buffer(9)]],                               \
      const constant float &softcapping [[buffer(10)]],                        \
      device const uint32_t *block_tables [[buffer(11)]],                      \
      device const uint32_t *context_lens [[buffer(12)]],                      \
      const constant int &max_num_blocks_per_seq [[buffer(13)]],               \
      const constant int &q_stride [[buffer(15)]],                             \
      const constant int &kv_block_stride [[buffer(16)]],                      \
      const constant int &kv_head_stride [[buffer(17)]],                       \
      device const float *sinks                                                \
      [[buffer(18), function_constant(use_sinks)]],                            \
      device const int32_t *cu_seqlens_q [[buffer(19)]],                       \
      const constant int &num_seqs [[buffer(20)]],                             \
      const constant int &sliding_window [[buffer(21)]],                       \
      device const int32_t *mm_prefix_ranges                                   \
      [[buffer(22), function_constant(use_mm_prefix)]],                        \
      threadgroup char *shared_mem [[threadgroup(0)]],                         \
      uint3 tgp [[threadgroup_position_in_grid]],                              \
      uint3 tgpg [[threadgroups_per_grid]],                                    \
      uint3 tpt [[thread_position_in_threadgroup]],                            \
      uint sg_idx [[simdgroup_index_in_threadgroup]],                          \
      uint lane [[thread_index_in_simdgroup]]);

// Each entry must match a (head_size -> TileConfig) row in select_tile_config
// in vllm_metal/metal/paged_ops.cpp.
#define instantiate_paged_attention_tiled_heads(type, block_size)              \
  instantiate_paged_attention_tiled_inner(type, 64,  block_size, 32, 32, 128, 1); \
  instantiate_paged_attention_tiled_inner(type, 96,  block_size, 32, 32, 128, 1); \
  instantiate_paged_attention_tiled_inner(type, 128, block_size, 32, 32, 128, 1); \
  instantiate_paged_attention_tiled_inner(type, 256, block_size, 16, 16,  64, 1); \
  instantiate_paged_attention_tiled_inner(type, 512, block_size,  8,  8, 128, 4);

#define instantiate_paged_attention_tiled_all(type)                            \
  instantiate_paged_attention_tiled_heads(type, 8);                            \
  instantiate_paged_attention_tiled_heads(type, 16);                           \
  instantiate_paged_attention_tiled_heads(type, 32);

instantiate_paged_attention_tiled_all(half);
instantiate_paged_attention_tiled_all(bfloat16_t);

// ─────────────────────────────────────────────────────────────────────────
// GQA-packed paged decode.
//
// The per-token decode kernel (paged_attention) runs one threadgroup per
// query head, so every KV head is streamed once per query head that shares
// it: 8x the KV traffic for Gemma 4's full-attention layers (16 q / 2 KV
// heads, head_dim 512).  Here one threadgroup serves up to 8 query heads of
// one KV head at a single decode position: they are the 8 rows of the MMA
// fragment, so each K/V tile is loaded once per KV head.  The four
// simdgroups split the head dimension like the tiled kernel's D_SPLIT
// configuration (partial S exchanged through S_xchg, each owns
// HEAD_SIZE / 4 columns of O); Q stays register-resident.
//
// Grid: x = KV head * ceil(G / 8) head groups (G = num_heads / num_kv_heads),
//       y = decode token (pure decode: one token per sequence),
//       z = KV partition (1 when PARTITION_SIZE == 0).
// PARTITION_SIZE > 0 writes paged_attention_v2_reduce partials: log2-space
// max, exp-sum and O / l in OUT_T (float).  PARTITION_SIZE == 0 writes the
// normalized output in T and folds attention sinks itself.
//
// exp2 is the precise function: the shaders build with -fno-fast-math and
// MLX's runtime compile disables fast math; only fast::exp2 is relaxed.
// ─────────────────────────────────────────────────────────────────────────
template <typename T, typename OUT_T, int HEAD_SIZE, int BLOCK_SIZE,
          int TILE_KV, int PARTITION_SIZE>
[[kernel]] void paged_attention_gqa_decode(
    device float *exp_sums
    [[buffer(0), function_constant(use_partitioning)]],
    device float *max_logits
    [[buffer(1), function_constant(use_partitioning)]],
    device OUT_T *out [[buffer(2)]],
    device const T *q [[buffer(3)]],
    device const T *k_cache [[buffer(4)]],
    device const T *v_cache [[buffer(5)]],
    const constant int &num_kv_heads [[buffer(8)]],
    const constant float &scale [[buffer(9)]],
    const constant float &softcapping [[buffer(10)]],
    device const uint32_t *block_tables [[buffer(11)]],
    device const uint32_t *context_lens [[buffer(12)]],
    const constant int &max_num_blocks_per_seq [[buffer(13)]],
    const constant int &q_stride [[buffer(15)]],
    const constant int &kv_block_stride [[buffer(16)]],
    const constant int &kv_head_stride [[buffer(17)]],
    device const float *sinks
    [[buffer(18), function_constant(use_sinks)]],
    const constant int &sliding_window [[buffer(21)]],
    const constant int &num_heads [[buffer(22)]],
    threadgroup char *shared_mem [[threadgroup(0)]],
    uint3 tgp [[threadgroup_position_in_grid]],
    uint3 tgpg [[threadgroups_per_grid]],
    uint3 tpt [[thread_position_in_threadgroup]],
    uint sg_idx [[simdgroup_index_in_threadgroup]],
    uint lane [[thread_index_in_simdgroup]])
{
  constexpr int ROWS = 8;               // query heads per threadgroup
  constexpr int NUM_THREADS = 128;
  constexpr int NUM_SIMD_LANES = 32;
  constexpr int D_SPLIT = NUM_THREADS / NUM_SIMD_LANES;  // 4 simdgroups
  constexpr int TD = HEAD_SIZE / 8;     // 8-wide head_dim fragments
  constexpr int TD_O = TD / D_SPLIT;    // fragments owned per simdgroup
  constexpr int TK = TILE_KV / 8;       // 8-wide key fragments per tile
  constexpr bool PARTITIONED = PARTITION_SIZE > 0;
  static_assert(TD % D_SPLIT == 0, "D_SPLIT must divide HEAD_SIZE / 8");
  static_assert(TILE_KV % 8 == 0 && TILE_KV % D_SPLIT == 0,
                "tile rows split evenly across simdgroups");
  static_assert(!PARTITIONED || PARTITION_SIZE % TILE_KV == 0,
                "partitions hold whole tiles");

  const int thread_idx = tpt.x;
  const int d_base = int(sg_idx) * TD_O;

  // ─ Query heads, sequence and KV range of this threadgroup ─────────────
  const int G = num_heads / num_kv_heads;
  const int groups_per_kv = (G + ROWS - 1) / ROWS;
  const int kv_head_idx = int(tgp.x) / groups_per_kv;
  const int group_in_kv = int(tgp.x) % groups_per_kv;
  const int head_base = kv_head_idx * G + group_in_kv * ROWS;
  const int valid_rows = min(ROWS, G - group_in_kv * ROWS);

  const int token_idx = int(tgp.y);   // pure decode: token == sequence
  const int seq_len = int(context_lens[token_idx]);
  const int partition_idx = int(tgp.z);
  const int max_num_partitions = int(tgpg.z);

  const int part_start = PARTITIONED ? partition_idx * PARTITION_SIZE : 0;
  if (PARTITIONED && part_start >= seq_len) {
    return;  // beyond this sequence: the reduce never reads it
  }
  const int part_end =
      PARTITIONED ? min(part_start + PARTITION_SIZE, seq_len) : seq_len;
  // The decode row sits at position seq_len - 1: it attends keys
  // [seq_len - sliding_window, seq_len) with a window, [0, seq_len) without.
  const int window_start =
      (sliding_window >= 0) ? max(0, seq_len - sliding_window) : 0;
  const int kv_first = max(part_start, window_start);

  if constexpr (PARTITIONED) {
    if (kv_first >= part_end) {
      // Every key of this partition lies left of the window: write the
      // neutral partial paged_attention writes (max 0, sum 0, zeros), which
      // the reduce weighs by zero.
      for (int r = 0; r < valid_rows; r++) {
        const int stat = (token_idx * num_heads + head_base + r)
                         * max_num_partitions + partition_idx;
        if (thread_idx == 0) {
          max_logits[stat] = 0.f;
          exp_sums[stat] = 0.f;
        }
        device OUT_T *o = out + int64_t(stat) * HEAD_SIZE;
        for (int d = thread_idx; d < HEAD_SIZE; d += NUM_THREADS) {
          o[d] = OUT_T(0);
        }
      }
      return;
    }
  }

  // ─ Threadgroup memory: Q (load only), K and V tiles, partial-S exchange ─
  constexpr int SMEM_PAD = 16 / sizeof(T);
  constexpr int LD = HEAD_SIZE + SMEM_PAD;
  threadgroup T *Q_smem = reinterpret_cast<threadgroup T *>(shared_mem);
  threadgroup T *K_smem = Q_smem + ROWS * LD;
  threadgroup T *V_smem = K_smem + TILE_KV * LD;
  threadgroup float *S_xchg =
      reinterpret_cast<threadgroup float *>(V_smem + TILE_KV * LD);

  // ─ Q rows: the group's query heads, zero beyond valid_rows ─────────────
  const device T *q_base =
      q + int64_t(token_idx) * q_stride + int64_t(head_base) * HEAD_SIZE;
  for (int i = thread_idx; i < ROWS * HEAD_SIZE; i += NUM_THREADS) {
    const int r = i / HEAD_SIZE;
    const int d = i % HEAD_SIZE;
    Q_smem[r * LD + d] = (r < valid_rows) ? q_base[r * HEAD_SIZE + d] : T(0);
  }
  threadgroup_barrier(mem_flags::mem_threadgroup);

  using vec2T = vec<T, 2>;
  using vec2F = vec<float, 2>;
  vec2T Qreg[TD_O];
  #pragma unroll
  for (int dd = 0; dd < TD_O; dd++) {
    simdgroup_matrix<T, 8, 8> tmp;
    simdgroup_load(tmp, Q_smem + (d_base + dd) * 8, LD);
    Qreg[dd] = reinterpret_cast<thread vec2T &>(tmp.thread_elements());
  }

  const short2 fc = frag_coord(ushort(lane));
  const short fm = fc.y;   // fragment row: query head within the group
  const short fn = fc.x;   // fragment column: key within an 8-key block

  float max_score = -INFINITY;
  float sum_score = 0.0f;
  vec2F Oreg[TD_O];
  #pragma unroll
  for (int dd = 0; dd < TD_O; dd++) {
    Oreg[dd] = vec2F(0.0f);
  }

  const device uint32_t *block_table =
      block_tables + int64_t(token_idx) * max_num_blocks_per_seq;
  const int kv_token_stride = num_kv_heads * kv_head_stride;
  const float scale_log2 = scale * M_LOG2E_F;

  constexpr int VEC_BYTES = (HEAD_SIZE >= 256) ? 16 : 8;
  constexpr int VEC = VEC_BYTES / int(sizeof(T));
  using vecLoadT = typename LoadUnit<VEC_BYTES>::type;
  static_assert(LD % VEC == 0, "smem row stride LD must be VEC-aligned");

  // ─ KV tiles of this partition ───────────────────────────────────────────
  // The first tile holds kv_first, an attended key, and every later tile
  // starts below part_end <= seq_len, so no tile is fully masked and the
  // running max is finite after the first tile.
  const int tile_begin = kv_first - kv_first % TILE_KV;
  for (int tile_start = tile_begin; tile_start < part_end;
       tile_start += TILE_KV) {
    #pragma unroll
    for (int t_iter = 0; t_iter < TILE_KV / D_SPLIT; t_iter++) {
      const int t = int(sg_idx) * (TILE_KV / D_SPLIT) + t_iter;
      const int kv_pos = tile_start + t;
      if (kv_pos < seq_len) {
        const int64_t pb = int64_t(block_table[kv_pos / BLOCK_SIZE]);
        const int64_t off = pb * kv_block_stride
            + (kv_pos % BLOCK_SIZE) * kv_token_stride
            + kv_head_idx * kv_head_stride;
        const device T *k_ptr = k_cache + off;
        const device T *v_ptr = v_cache + off;
        #pragma unroll
        for (int d = int(lane) * VEC; d < HEAD_SIZE;
             d += NUM_SIMD_LANES * VEC) {
          *((threadgroup vecLoadT *)&K_smem[t * LD + d]) =
              *((const device vecLoadT *)(k_ptr + d));
          *((threadgroup vecLoadT *)&V_smem[t * LD + d]) =
              *((const device vecLoadT *)(v_ptr + d));
        }
      } else {
        const vecLoadT zero = {};
        #pragma unroll
        for (int d = int(lane) * VEC; d < HEAD_SIZE;
             d += NUM_SIMD_LANES * VEC) {
          *((threadgroup vecLoadT *)&K_smem[t * LD + d]) = zero;
          *((threadgroup vecLoadT *)&V_smem[t * LD + d]) = zero;
        }
      }
    }
    threadgroup_barrier(mem_flags::mem_threadgroup);  // K and V visible

    // S[8 heads, TILE_KV] over this simdgroup's head_dim columns.
    vec2F Sreg[TK];
    #pragma unroll
    for (int k = 0; k < TK; k++) {
      Sreg[k] = vec2F(0.0f);
    }
    #pragma unroll
    for (int dd = 0; dd < TD_O; dd++) {
      simdgroup_matrix<T, 8, 8> q_frag;
      reinterpret_cast<thread vec2T &>(q_frag.thread_elements()) = Qreg[dd];
      #pragma unroll
      for (int k = 0; k < TK; k++) {
        simdgroup_matrix<T, 8, 8> k_frag;
        simdgroup_load(k_frag, K_smem + k * 8 * LD + (d_base + dd) * 8, LD,
                       ulong2(0), /*transpose=*/true);
        simdgroup_matrix<float, 8, 8> s_frag;
        reinterpret_cast<thread vec2F &>(s_frag.thread_elements()) = Sreg[k];
        simdgroup_multiply_accumulate(s_frag, q_frag, k_frag, s_frag);
        Sreg[k] = reinterpret_cast<thread vec2F &>(s_frag.thread_elements());
      }
    }

    // Sum the four partial S fragments (one per head_dim quarter).
    #pragma unroll
    for (int k = 0; k < TK; k++) {
      simdgroup_matrix<float, 8, 8> part;
      reinterpret_cast<thread vec2F &>(part.thread_elements()) = Sreg[k];
      simdgroup_store(part, S_xchg + (int(sg_idx) * TK + k) * 64, 8);
    }
    threadgroup_barrier(mem_flags::mem_threadgroup);
    #pragma unroll
    for (int k = 0; k < TK; k++) {
      vec2F acc = vec2F(0.0f);
      #pragma unroll
      for (int p = 0; p < D_SPLIT; p++) {
        simdgroup_matrix<float, 8, 8> part;
        simdgroup_load(part, S_xchg + (p * TK + k) * 64, 8);
        acc += reinterpret_cast<thread vec2F &>(part.thread_elements());
      }
      Sreg[k] = acc;
    }

    // Scale, softcap, and mask keys outside [window_start, seq_len).
    const bool tile_unmasked = tile_start >= window_start
                               && tile_start + TILE_KV <= seq_len
                               && softcapping <= 0.0f;
    if (tile_unmasked) {
      #pragma unroll
      for (int k = 0; k < TK; k++) {
        Sreg[k] *= scale_log2;
      }
    } else {
      #pragma unroll
      for (int k = 0; k < TK; k++) {
        #pragma unroll
        for (int jj = 0; jj < 2; jj++) {
          float s = Sreg[k][jj] * scale_log2;
          if (softcapping > 0.0f) {
            const float s_orig = s / M_LOG2E_F;
            s = softcapping * precise::tanh(s_orig / softcapping) * M_LOG2E_F;
          }
          const int kv_pos = tile_start + k * 8 + fn + jj;
          const bool masked = kv_pos >= seq_len || kv_pos < window_start;
          Sreg[k][jj] = masked ? -INFINITY : s;
        }
      }
    }

    // Online softmax per query head (fragment row), in log2 space.
    float local_max = -INFINITY;
    #pragma unroll
    for (int k = 0; k < TK; k++) {
      local_max = max(local_max, max(Sreg[k][0], Sreg[k][1]));
    }
    const float row_max = frag_row_reduce<FragMax>(local_max);
    float new_max = max(max_score, row_max);
    float factor;
    if (new_max > max_score) {
      factor = (max_score == -INFINITY) ? 0.0f : exp2(max_score - new_max);
    } else {
      factor = 1.0f;
      if (max_score == -INFINITY) new_max = 0.0f;
    }
    max_score = new_max;

    float local_sum = 0.0f;
    #pragma unroll
    for (int k = 0; k < TK; k++) {
      #pragma unroll
      for (int jj = 0; jj < 2; jj++) {
        const float p = (Sreg[k][jj] == -INFINITY)
                            ? 0.0f
                            : exp2(Sreg[k][jj] - new_max);
        Sreg[k][jj] = p;
        local_sum += p;
      }
    }
    sum_score = sum_score * factor + frag_row_reduce<FragSum>(local_sum);

    #pragma unroll
    for (int dd = 0; dd < TD_O; dd++) {
      Oreg[dd] *= factor;
    }

    // O += P V over this simdgroup's head_dim columns.
    #pragma unroll
    for (int k = 0; k < TK; k++) {
      simdgroup_matrix<float, 8, 8> p_frag;
      reinterpret_cast<thread vec2F &>(p_frag.thread_elements()) = Sreg[k];
      #pragma unroll
      for (int dd = 0; dd < TD_O; dd++) {
        simdgroup_matrix<T, 8, 8> v_frag;
        simdgroup_load(v_frag, V_smem + k * 8 * LD + (d_base + dd) * 8, LD);
        simdgroup_matrix<float, 8, 8> o_frag;
        reinterpret_cast<thread vec2F &>(o_frag.thread_elements()) = Oreg[dd];
        simdgroup_multiply_accumulate(o_frag, p_frag, v_frag, o_frag);
        Oreg[dd] = reinterpret_cast<thread vec2F &>(o_frag.thread_elements());
      }
    }
    // K_smem, V_smem and S_xchg are rewritten by the next tile.
    threadgroup_barrier(mem_flags::mem_threadgroup);
  }

  const int head = head_base + fm;
  const bool row_valid = fm < valid_rows;

  if constexpr (PARTITIONED) {
    // One lane per row (fn == 0) of the first simdgroup stores the stats;
    // the reduce folds attention sinks once across partitions.
    if (sg_idx == 0 && fn == 0 && row_valid) {
      const int stat =
          (token_idx * num_heads + head) * max_num_partitions + partition_idx;
      max_logits[stat] = max_score;
      exp_sums[stat] = sum_score;
    }
  } else {
    if (use_sinks && row_valid) {
      const float sink_score = sinks[head] * M_LOG2E_F;
      const float sink_max = max(max_score, sink_score);
      const float old_corr =
          (max_score == -INFINITY) ? 0.0f : exp2(max_score - sink_max);
      sum_score = sum_score * old_corr + exp2(sink_score - sink_max);
      max_score = sink_max;
      #pragma unroll
      for (int dd = 0; dd < TD_O; dd++) {
        Oreg[dd] *= old_corr;
      }
    }
  }

  const float inv_sum = 1.0f / (sum_score + 1e-6f);
  #pragma unroll
  for (int dd = 0; dd < TD_O; dd++) {
    Oreg[dd] *= inv_sum;
  }

  // Stage O as fp32 over the Q/K region (8 * LD floats fit in Q + K + V for
  // every instantiated TILE_KV) and write the valid rows.
  threadgroup float *O_smem = reinterpret_cast<threadgroup float *>(shared_mem);
  #pragma unroll
  for (int dd = 0; dd < TD_O; dd++) {
    simdgroup_matrix<float, 8, 8> o_frag;
    reinterpret_cast<thread vec2F &>(o_frag.thread_elements()) = Oreg[dd];
    simdgroup_store(o_frag, O_smem + (d_base + dd) * 8, LD);
  }
  threadgroup_barrier(mem_flags::mem_threadgroup);

  for (int i = thread_idx; i < valid_rows * HEAD_SIZE; i += NUM_THREADS) {
    const int r = i / HEAD_SIZE;
    const int d = i % HEAD_SIZE;
    const float v = O_smem[r * LD + d];
    if constexpr (PARTITIONED) {
      const int stat = (token_idx * num_heads + head_base + r)
                       * max_num_partitions + partition_idx;
      out[int64_t(stat) * HEAD_SIZE + d] = OUT_T(v);
    } else {
      out[int64_t(token_idx) * q_stride + int64_t(head_base + r) * HEAD_SIZE
          + d] = OUT_T(v);
    }
  }
}

#define instantiate_paged_attention_gqa_decode_inner(                          \
    type, out_type, head_size, block_size, tile_kv, ps)                        \
  template [[host_name("paged_attention_gqa_decode_" #type                     \
                       "_hs" #head_size "_bs" #block_size                      \
                       "_tk" #tile_kv "_ps" #ps)]]                             \
  [[kernel]] void paged_attention_gqa_decode<type, out_type, head_size,        \
                                             block_size, tile_kv, ps>(         \
      device float *exp_sums                                                   \
      [[buffer(0), function_constant(use_partitioning)]],                      \
      device float *max_logits                                                 \
      [[buffer(1), function_constant(use_partitioning)]],                      \
      device out_type *out [[buffer(2)]],                                      \
      device const type *q [[buffer(3)]],                                      \
      device const type *k_cache [[buffer(4)]],                                \
      device const type *v_cache [[buffer(5)]],                                \
      const constant int &num_kv_heads [[buffer(8)]],                          \
      const constant float &scale [[buffer(9)]],                               \
      const constant float &softcapping [[buffer(10)]],                        \
      device const uint32_t *block_tables [[buffer(11)]],                      \
      device const uint32_t *context_lens [[buffer(12)]],                      \
      const constant int &max_num_blocks_per_seq [[buffer(13)]],               \
      const constant int &q_stride [[buffer(15)]],                             \
      const constant int &kv_block_stride [[buffer(16)]],                      \
      const constant int &kv_head_stride [[buffer(17)]],                       \
      device const float *sinks                                                \
      [[buffer(18), function_constant(use_sinks)]],                            \
      const constant int &sliding_window [[buffer(21)]],                       \
      const constant int &num_heads [[buffer(22)]],                            \
      threadgroup char *shared_mem [[threadgroup(0)]],                         \
      uint3 tgp [[threadgroup_position_in_grid]],                              \
      uint3 tgpg [[threadgroups_per_grid]],                                    \
      uint3 tpt [[thread_position_in_threadgroup]],                            \
      uint sg_idx [[simdgroup_index_in_threadgroup]],                          \
      uint lane [[thread_index_in_simdgroup]]);

// (head_size -> TILE_KV) must match gqa_decode_tile_kv() in paged_ops.cpp.
#define instantiate_paged_attention_gqa_decode_ps(type, out_type, block_size,  \
                                                  ps)                          \
  instantiate_paged_attention_gqa_decode_inner(type, out_type, 128,            \
                                               block_size, 32, ps);            \
  instantiate_paged_attention_gqa_decode_inner(type, out_type, 256,            \
                                               block_size, 16, ps);            \
  instantiate_paged_attention_gqa_decode_inner(type, out_type, 512,            \
                                               block_size, 8, ps);

#define instantiate_paged_attention_gqa_decode_block(type, block_size)         \
  instantiate_paged_attention_gqa_decode_ps(type, type, block_size, 0);        \
  instantiate_paged_attention_gqa_decode_ps(type, float, block_size, 256);     \
  instantiate_paged_attention_gqa_decode_ps(type, float, block_size, 512);

#define instantiate_paged_attention_gqa_decode_all(type)                       \
  instantiate_paged_attention_gqa_decode_block(type, 8);                       \
  instantiate_paged_attention_gqa_decode_block(type, 16);                      \
  instantiate_paged_attention_gqa_decode_block(type, 32);

instantiate_paged_attention_gqa_decode_all(half);
instantiate_paged_attention_gqa_decode_all(bfloat16_t);
