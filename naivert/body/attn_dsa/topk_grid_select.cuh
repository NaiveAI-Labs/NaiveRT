// Grid-parallel exact top-k selection for the attn_dsa sparse regime.
// Included inside AttnDsaBody after index_topk_stage.cuh.
//
// The shared stage finds the rank-2048 threshold with a block radix sort in one CTA per query
// (over at most kThreads * kTopKSortItemsPerThread = 8448 keys, so it is wrong past that) and
// then sorts the compacted selections to make their order deterministic. Here every CTA takes
// part, and the result is the same set as the sorted definition (value descending, index
// ascending on ties) for any number of visible tokens, in ascending token order.
//
// Two 8-bit digit passes over the ordered 32-bit keys (float4 per thread) histogram into
// per-CTA shared counters and merge with one global add per non-empty bin per CTA (the top
// bytes of the keys fall into a handful of bins, so direct global atomics serialised there).
// They fix the 16-bit prefix of the threshold. A compaction pass then lists, per query, the
// tokens whose keys lie strictly above that prefix ("above", fewer than 2048 of them) and the
// tokens equal to it (the candidates, with their keys). When every query's candidate list fits
// kTopKCandidateCap, one CTA per query finishes alone: the two low digits over the candidates
// in shared memory, then the winners (above, candidates above the exact threshold, the
// lowest-index ties) sorted by token with a block radix sort. Otherwise (a degenerate key
// distribution), and below kTopKCompactMinVisible tokens where the per-query finish's fixed
// cost is not worth it, the full passes finish the selection over all keys.
//
// Workspace (Scratch::kTopKGridOffset, per query): hist[4][kTopKGridBins], count_gt /
// count_eq / prefix_gt / prefix_eq [kTopKCountSlots], counters[2] (above, candidates),
// above[kIndexTopK], candidate_token[cap], candidate_key[cap]. The histograms and counters
// must be zero before the passes: zero_topk_grid() runs in every CTA before the projection
// barrier.

  static constexpr int kTopKGridBins = 256;
  static constexpr int kTopKGridPasses = 4;
  static constexpr int kTopKChunk = kThreads;  // fallback count/write chunk: one token per thread
  static constexpr int kTopKVec = 4;           // floats per thread per scan step (float4 loads)
  static constexpr int kTopKScanChunk = kThreads * kTopKVec;   // tokens per scan work item
  static constexpr int kTopKMaxChunks =
      (Scratch::kMaxSeqLen + Scratch::kQueryRows + kTopKChunk - 1) / kTopKChunk;
  static constexpr int kTopKCountSlots = 4096;
  static_assert(kTopKMaxChunks <= kTopKCountSlots, "chunk counts per query must fit");
  static_assert(Scratch::kMaxSeqLen % kTopKVec == 0, "float4 scans need a padded logits row");
  static constexpr int kTopKGridHistWords = kTopKGridPasses * kTopKGridBins;
  static constexpr int kTopKCandidateCap = 8192;   // candidates (equal 16-bit prefix) per query
  // Below this many visible tokens the full passes (two more digit passes, count, prefix,
  // ordered write: no sort) beat the compaction + per-query finish (~10 us fixed).
  static constexpr int kTopKCompactMinVisible = 16384;
  static constexpr int kTopKAboveWords = Scratch::kIndexTopK;
  static constexpr int kTopKCounterWords = 2;
  static constexpr int kTopKGridWordsPerQuery = kTopKGridHistWords + 4 * kTopKCountSlots +
                                                kTopKCounterWords + kTopKAboveWords +
                                                2 * kTopKCandidateCap;
  static_assert(Scratch::kTopKGridBytes ==
                    std::size_t(Scratch::kQueryRows) * kTopKGridWordsPerQuery * sizeof(unsigned),
                "top-k grid workspace layout");
  static constexpr int kTopKPositionBits = 21;
  static_assert(Scratch::kMaxSeqLen + Scratch::kQueryRows <= (1 << kTopKPositionBits),
                "token sorts of the grid finish use kTopKPositionBits");
  // Shared words used by select_per_query_topk_grid (carved from the top-k sort storage, which
  // the per-query finish then reuses for its block sorts): header, then the per-query 256-bin
  // histograms of the current pass.
  static constexpr int kTopKGridSharedHeader = 128;
  static constexpr int kTopKGridSharedWords =
      kTopKGridSharedHeader + Scratch::kQueryRows * kTopKGridBins;
  static_assert(sizeof(SharedStorage) >= kTopKGridSharedWords * sizeof(unsigned),
                "top-k grid selection must fit shared storage");
  static_assert(kThreads * kTopKSortItemsPerThread >= kTopKCandidateCap,
                "the per-query finish sorts the candidate ties with the block radix sort");
  static_assert(kThreads == 384, "SelectionSort (384 x 6) sorts the winners of the grid finish");

  __device__ __forceinline__ static unsigned* topk_grid_hist(unsigned* base, int query, int pass) {
    return base + std::size_t(query) * kTopKGridWordsPerQuery + pass * kTopKGridBins;
  }
  __device__ __forceinline__ static unsigned* topk_grid_count_gt(unsigned* base, int query) {
    return base + std::size_t(query) * kTopKGridWordsPerQuery + kTopKGridHistWords;
  }
  __device__ __forceinline__ static unsigned* topk_grid_count_eq(unsigned* base, int query) {
    return topk_grid_count_gt(base, query) + kTopKCountSlots;
  }
  __device__ __forceinline__ static unsigned* topk_grid_prefix_gt(unsigned* base, int query) {
    return topk_grid_count_eq(base, query) + kTopKCountSlots;
  }
  __device__ __forceinline__ static unsigned* topk_grid_prefix_eq(unsigned* base, int query) {
    return topk_grid_prefix_gt(base, query) + kTopKCountSlots;
  }
  __device__ __forceinline__ static unsigned* topk_grid_counters(unsigned* base, int query) {
    return topk_grid_prefix_eq(base, query) + kTopKCountSlots;
  }
  __device__ __forceinline__ static unsigned* topk_grid_above(unsigned* base, int query) {
    return topk_grid_counters(base, query) + kTopKCounterWords;
  }
  __device__ __forceinline__ static unsigned* topk_grid_candidate_token(unsigned* base, int query) {
    return topk_grid_above(base, query) + kTopKAboveWords;
  }
  __device__ __forceinline__ static unsigned* topk_grid_candidate_key(unsigned* base, int query) {
    return topk_grid_candidate_token(base, query) + kTopKCandidateCap;
  }

  // Every CTA zeroes a slice of every query's histograms; CTA 0 the list counters (before the
  // projection barrier).
  __device__ static void zero_topk_grid(unsigned* base) {
    const int stride = int(gridDim.x) * kThreads;
    for (int query = 0; query < Scratch::kQueryRows; ++query) {
      unsigned* hist = topk_grid_hist(base, query, 0);
      for (int i = int(blockIdx.x) * kThreads + int(threadIdx.x); i < kTopKGridHistWords;
           i += stride) {
        hist[i] = 0u;
      }
      if (int(blockIdx.x) == 0 && int(threadIdx.x) < kTopKCounterWords) {
        topk_grid_counters(base, query)[threadIdx.x] = 0u;
      }
    }
  }

  // Warp-level exclusive scan (lane order). Returns the exclusive prefix; *total gets the sum.
  __device__ __forceinline__ static unsigned topk_warp_exclusive_scan(unsigned value, int lane,
                                                                      unsigned* total) {
    unsigned inclusive = value;
#pragma unroll
    for (int offset = 1; offset < 32; offset <<= 1) {
      const unsigned previous = __shfl_up_sync(0xffffffffu, inclusive, offset);
      if (lane >= offset) {
        inclusive += previous;
      }
    }
    *total = __shfl_sync(0xffffffffu, inclusive, 31);
    return inclusive - value;
  }

  // One warp per query: find the histogram bin holding the `wanted`-th largest key and the
  // rank inside it (1-based). Lanes own eight consecutive bins each, highest bins first, so the
  // walk is deterministic; every CTA computes the same answer. out[0] = bin, out[1] = rank.
  __device__ __forceinline__ static void topk_grid_find_bin_warp(const unsigned* hist,
                                                                 unsigned wanted, int lane,
                                                                 unsigned* out) {
    constexpr int kBinsPerLane = kTopKGridBins / 32;  // 8
    unsigned mine[kBinsPerLane];
    unsigned sum = 0u;
#pragma unroll
    for (int i = 0; i < kBinsPerLane; ++i) {
      mine[i] = hist[kTopKGridBins - 1 - (lane * kBinsPerLane + i)];
      sum += mine[i];
    }
    unsigned total = 0u;
    unsigned above = topk_warp_exclusive_scan(sum, lane, &total);
#pragma unroll
    for (int i = 0; i < kBinsPerLane; ++i) {
      if (above < wanted && wanted <= above + mine[i]) {
        out[0] = unsigned(kTopKGridBins - 1 - (lane * kBinsPerLane + i));
        out[1] = wanted - above;
      }
      above += mine[i];
    }
    __syncwarp();
  }

  // One warp per query: exclusive prefix of the chunk counts, in chunk order.
  __device__ __forceinline__ static void topk_grid_chunk_prefix_warp(const unsigned* counts,
                                                                     int chunks, int lane,
                                                                     unsigned* prefix_out) {
    unsigned carry = 0u;
    for (int chunk0 = 0; chunk0 < chunks; chunk0 += 32) {
      const int chunk = chunk0 + lane;
      const unsigned value = chunk < chunks ? counts[chunk] : 0u;
      unsigned total = 0u;
      const unsigned before = topk_warp_exclusive_scan(value, lane, &total);
      if (chunk < chunks) {
        prefix_out[chunk] = carry + before;
      }
      carry += total;
    }
    __syncwarp();
  }

  // Four consecutive logits of one query (the row is padded to kMaxSeqLen, a multiple of 4, so
  // the float4 is always readable; elements past `visible` are masked by the callers).
  __device__ __forceinline__ static float4 topk_grid_load4(const float* logits, int query,
                                                           int token0, int visible) {
    if (token0 < visible) {
      return *reinterpret_cast<const float4*>(logits + std::size_t(query) * Scratch::kMaxSeqLen +
                                              token0);
    }
    return make_float4(0.0f, 0.0f, 0.0f, 0.0f);
  }

  // One 8-bit digit pass over the keys matching the prefix so far: per-CTA shared histograms
  // (warp-aggregated shared atomics), then one global add per non-empty bin.
  __device__ static void topk_grid_digit_pass(const float* logits, unsigned* grid_base,
                                              int base_pos, int scan_chunks, int scan_items,
                                              int pass, const unsigned* prefix,
                                              unsigned* shared_hist) {
    const int tid = int(threadIdx.x);
    const int lane = tid & 31;
    const int shift = 24 - 8 * pass;
    const unsigned prefix_mask = pass == 0 ? 0u : (0xffffffffu << unsigned(shift + 8));
    for (int i = tid; i < Scratch::kQueryRows * kTopKGridBins; i += kThreads) {
      shared_hist[i] = 0u;
    }
    __syncthreads();
    for (int item = int(blockIdx.x); item < scan_items; item += int(gridDim.x)) {
      const int query = item / scan_chunks;
      const int chunk = item - query * scan_chunks;
      const int token0 = chunk * kTopKScanChunk + tid * kTopKVec;
      const int visible = base_pos + query + 1;
      const unsigned want = prefix[query];
      const float4 v = topk_grid_load4(logits, query, token0, visible);
      const float vals[kTopKVec] = {v.x, v.y, v.z, v.w};
      unsigned* hist = shared_hist + query * kTopKGridBins;
#pragma unroll
      for (int j = 0; j < kTopKVec; ++j) {
        unsigned digit = 0xffffffffu;
        if (token0 + j < visible) {
          const unsigned key = ordered_float_key(vals[j]);
          if ((key & prefix_mask) == want) {
            digit = (key >> unsigned(shift)) & 0xffu;
          }
        }
        if (digit != 0xffffffffu) {
          atomicAdd(hist + digit, 1u);
        }
      }
    }
    __syncthreads();
    for (int i = tid; i < Scratch::kQueryRows * kTopKGridBins; i += kThreads) {
      const unsigned count = shared_hist[i];
      if (count != 0u) {
        atomicAdd(topk_grid_hist(grid_base, i / kTopKGridBins, pass) + (i % kTopKGridBins), count);
      }
    }
    __syncthreads();
  }

  // Append this warp's flagged tokens to a per-query list (one atomic per warp, unordered;
  // entries past `cap` are dropped, the counter keeps counting).
  __device__ __forceinline__ static void topk_grid_append_warp(bool flag, unsigned token,
                                                               unsigned key, unsigned* counter,
                                                               unsigned* tokens, unsigned* keys,
                                                               unsigned cap, int lane) {
    const unsigned mask = __ballot_sync(0xffffffffu, flag);
    if (mask == 0u) {
      return;
    }
    unsigned base = 0u;
    if (lane == 0) {
      base = atomicAdd(counter, unsigned(__popc(mask)));
    }
    base = __shfl_sync(0xffffffffu, base, 0);
    if (flag) {
      const unsigned slot = base + unsigned(__popc(mask & ((1u << unsigned(lane)) - 1u)));
      if (slot < cap) {
        tokens[slot] = token;
        if (keys != nullptr) {
          keys[slot] = key;
        }
      }
    }
  }

  // Fallback: passes 2..3 over all keys, chunk counts, prefixes, ordered write.
  __device__ static void topk_grid_full_finish(const float* logits, int* selections,
                                               unsigned* grid_base, int base_pos, int chunks,
                                               int items, int scan_chunks, int scan_items,
                                               float* attention_temp, unsigned* shared_words,
                                               unsigned* shared_hist) {
    auto grid = cg::this_grid();
    const int tid = int(threadIdx.x);
    const int warp = tid >> 5;
    const int lane = tid & 31;
    const unsigned lower_lanes = lane == 0 ? 0u : (1u << unsigned(lane)) - 1u;
    unsigned* warp_gt = shared_words + 32;                // [16]
    unsigned* warp_eq = shared_words + 48;                // [16]
    unsigned* bin_out = shared_words + 64;                // [2 * kQueryRows]
    unsigned* prefix = shared_words + 96;                 // [kQueryRows] threshold key so far
    unsigned* wanted = shared_words + 112;                // [kQueryRows] rank still wanted
#pragma unroll 1
    for (int pass = 2; pass < kTopKGridPasses; ++pass) {
      const int shift = 24 - 8 * pass;
      topk_grid_digit_pass(logits, grid_base, base_pos, scan_chunks, scan_items, pass, prefix,
                           shared_hist);
      grid.sync();
      record_phase(attention_temp, 4 + pass);
      if (warp < Scratch::kQueryRows) {
        topk_grid_find_bin_warp(topk_grid_hist(grid_base, warp, pass), wanted[warp], lane,
                                bin_out + 2 * warp);
      }
      __syncthreads();
      if (tid < Scratch::kQueryRows) {
        prefix[tid] |= bin_out[2 * tid] << unsigned(shift);
        wanted[tid] = bin_out[2 * tid + 1];
      }
      __syncthreads();
    }
    record_phase(attention_temp, 10);
    // Count pass: per (query, chunk), keys above and keys equal to the threshold.
    for (int item = int(blockIdx.x); item < items; item += int(gridDim.x)) {
      const int query = item / chunks;
      const int chunk = item - query * chunks;
      const int token = chunk * kTopKChunk + tid;
      bool gt = false;
      bool eq = false;
      if (token < base_pos + query + 1) {
        const unsigned key = ordered_float_key(
            logits[std::size_t(query) * Scratch::kMaxSeqLen + token]);
        gt = key > prefix[query];
        eq = key == prefix[query];
      }
      const int n_gt = __syncthreads_count(gt);
      const int n_eq = __syncthreads_count(eq);
      if (tid == 0) {
        topk_grid_count_gt(grid_base, query)[chunk] = unsigned(n_gt);
        topk_grid_count_eq(grid_base, query)[chunk] = unsigned(n_eq);
      }
    }
    grid.sync();
    record_phase(attention_temp, 11);
    // Exclusive prefix of the chunk counts per query, written to global (CTA 0, one warp per
    // query) so it scales past shared memory; a grid barrier publishes it to the write pass.
    if (int(blockIdx.x) == 0 && warp < Scratch::kQueryRows) {
      topk_grid_chunk_prefix_warp(topk_grid_count_gt(grid_base, warp), chunks, lane,
                                  topk_grid_prefix_gt(grid_base, warp));
      topk_grid_chunk_prefix_warp(topk_grid_count_eq(grid_base, warp), chunks, lane,
                                  topk_grid_prefix_eq(grid_base, warp));
    }
    grid.sync();
    // Write pass: slot = (keys above the threshold before this token) + (tied keys taken
    // before it); tied keys are taken in ascending token order until `wanted` are placed.
    for (int item = int(blockIdx.x); item < items; item += int(gridDim.x)) {
      const int query = item / chunks;
      const int chunk = item - query * chunks;
      const int token = chunk * kTopKChunk + tid;
      const unsigned threshold = prefix[query];
      const unsigned ties_needed = wanted[query];
      bool gt = false;
      bool eq = false;
      if (token < base_pos + query + 1) {
        const unsigned key = ordered_float_key(
            logits[std::size_t(query) * Scratch::kMaxSeqLen + token]);
        gt = key > threshold;
        eq = key == threshold;
      }
      const unsigned gt_mask = __ballot_sync(0xffffffffu, gt);
      const unsigned eq_mask = __ballot_sync(0xffffffffu, eq);
      if (lane == 0) {
        warp_gt[warp] = unsigned(__popc(gt_mask));
        warp_eq[warp] = unsigned(__popc(eq_mask));
      }
      __syncthreads();
      unsigned gt_before = topk_grid_prefix_gt(grid_base, query)[chunk];
      unsigned eq_before = topk_grid_prefix_eq(grid_base, query)[chunk];
#pragma unroll
      for (int w = 0; w < kWmmaWarps; ++w) {
        gt_before += w < warp ? warp_gt[w] : 0u;
        eq_before += w < warp ? warp_eq[w] : 0u;
      }
      gt_before += unsigned(__popc(gt_mask & lower_lanes));
      eq_before += unsigned(__popc(eq_mask & lower_lanes));
      const bool selected = gt || (eq && eq_before < ties_needed);
      if (selected) {
        const unsigned slot = gt_before + (eq_before < ties_needed ? eq_before : ties_needed);
        selections[query * Scratch::kIndexTopK + int(slot)] = token;
      }
      __syncthreads();
    }
    grid.sync();
  }

  // One CTA per query: the two low digits over the candidates in shared memory, then
  // the winners assembled and sorted by token. prefix16 = the 16-bit prefix found by the grid
  // passes (in the top bits), wanted16 = the rank still wanted inside it. The block sorts
  // reuse the shared storage, so every value they need is in registers first.
  __device__ static void topk_grid_query_finish(int* selections, unsigned* grid_base, int query,
                                                unsigned prefix16, unsigned wanted16,
                                                unsigned* shared_words, unsigned* shared_hist,
                                                TopKBlockRadixSort::TempStorage* sort_storage) {
    const int tid = int(threadIdx.x);
    const int warp = tid >> 5;
    const int lane = tid & 31;
    unsigned* bin_out = shared_words + 64;   // [2]
    unsigned* state = shared_words + 96;     // [0] prefix [1] wanted [2] above [3] cands
                                             // [4] fill [5] ties present
    unsigned* hist = shared_hist;            // [256]
    const unsigned* counters = topk_grid_counters(grid_base, query);
    const unsigned* cand_token = topk_grid_candidate_token(grid_base, query);
    const unsigned* cand_key = topk_grid_candidate_key(grid_base, query);
    const unsigned* above = topk_grid_above(grid_base, query);
    int* out = selections + query * Scratch::kIndexTopK;
    __syncthreads();   // the caller's shared header has been read by every thread
    if (tid == 0) {
      state[0] = prefix16;
      state[1] = wanted16;
      state[2] = counters[0];
      state[3] = counters[1];
      state[4] = counters[0];
      state[5] = 0u;
    }
    __syncthreads();
    const int n_above = int(state[2]);
    const int n_cand = int(state[3]);
    // Passes 2 and 3 over the candidates (they all carry the 16-bit prefix).
#pragma unroll 1
    for (int pass = 2; pass < kTopKGridPasses; ++pass) {
      const int shift = 24 - 8 * pass;
      const unsigned prefix_mask = 0xffffffffu << unsigned(shift + 8);
      for (int i = tid; i < kTopKGridBins; i += kThreads) {
        hist[i] = 0u;
      }
      __syncthreads();
      const unsigned want = state[0];
      for (int i = tid; i < n_cand; i += kThreads) {
        const unsigned key = cand_key[i];
        if ((key & prefix_mask) == want) {
          atomicAdd(hist + ((key >> unsigned(shift)) & 0xffu), 1u);
        }
      }
      __syncthreads();
      if (warp == 0) {
        topk_grid_find_bin_warp(hist, state[1], lane, bin_out);
      }
      __syncthreads();
      if (tid == 0) {
        state[0] |= bin_out[0] << unsigned(shift);
        state[1] = bin_out[1];
      }
      __syncthreads();
    }
    const unsigned threshold = state[0];
    const unsigned ties_needed = state[1];
    // Winners, unordered: (a) every token above the prefix, (b) the candidates above the exact
    // threshold (counting the ties on the way).
    for (int i = tid; i < n_above; i += kThreads) {
      out[i] = int(above[i]);
    }
    for (int i = tid; i < n_cand; i += kThreads) {
      const unsigned key = cand_key[i];
      if (key > threshold) {
        const unsigned slot = atomicAdd(state + 4, 1u);
        out[slot] = int(cand_token[i]);
      } else if (key == threshold) {
        atomicAdd(state + 5, 1u);
      }
    }
    __syncthreads();
    const unsigned fill = state[4];
    const unsigned ties_present = state[5];
    __syncthreads();
    if (ties_present <= ties_needed) {
      // (c) every tie is a winner (ties_present == ties_needed); order comes from the final sort.
      for (int i = tid; i < n_cand; i += kThreads) {
        if (cand_key[i] == threshold) {
          const unsigned slot = atomicAdd(state + 4, 1u);
          out[slot] = int(cand_token[i]);
        }
      }
      __syncthreads();
    } else {
      // (c) the ties_needed lowest tokens among the ties: block radix sort of the tie tokens
      //     (blocked arrangement: thread t holds sorted ranks t*items .. t*items+items-1).
      unsigned items[kTopKSortItemsPerThread];
#pragma unroll
      for (int j = 0; j < kTopKSortItemsPerThread; ++j) {
        const int i = tid + j * kThreads;
        items[j] = (i < n_cand && cand_key[i] == threshold) ? cand_token[i] : 0xffffffffu;
      }
      __syncthreads();
      TopKBlockRadixSort(*sort_storage).Sort(items, 0, kTopKPositionBits);
#pragma unroll
      for (int j = 0; j < kTopKSortItemsPerThread; ++j) {
        const int rank = tid * kTopKSortItemsPerThread + j;
        if (rank < int(ties_needed)) {
          out[int(fill) + rank] = int(items[j]);
        }
      }
      __syncthreads();
    }
    // Ascending token order (the attention sum order, hence the output bits, is then stable).
    {
      constexpr int kItems = 6;
      static_assert(kThreads * kItems >= Scratch::kIndexTopK, "winner sort capacity");
      unsigned keys[kItems];
#pragma unroll
      for (int j = 0; j < kItems; ++j) {
        const int index = tid * kItems + j;
        keys[j] = index < Scratch::kIndexTopK ? unsigned(out[index]) : 0xffffffffu;
      }
      __syncthreads();
      SelectionSort(*reinterpret_cast<typename SelectionSort::TempStorage*>(sort_storage))
          .Sort(keys, 0, kTopKPositionBits);
#pragma unroll
      for (int j = 0; j < kItems; ++j) {
        const int index = tid * kItems + j;
        if (index < Scratch::kIndexTopK) {
          out[index] = int(keys[j]);
        }
      }
      __syncthreads();
    }
  }

  __device__ static void select_per_query_topk_grid(const float* logits, int* selections,
                                                    unsigned* grid_base, int base_pos,
                                                    float* attention_temp,
                                                    unsigned* shared_words,
                                                    TopKBlockRadixSort::TempStorage* sort_storage) {
    auto grid = cg::this_grid();
    const int tid = int(threadIdx.x);
    const int warp = tid >> 5;
    const int lane = tid & 31;
    unsigned* bin_out = shared_words + 64;                // [2 * kQueryRows]
    unsigned* prefix = shared_words + 96;                 // [kQueryRows] threshold key so far
    unsigned* wanted = shared_words + 112;                // [kQueryRows] rank still wanted
    unsigned* shared_hist = shared_words + kTopKGridSharedHeader;  // [kQueryRows][256]
    static_assert(Scratch::kQueryRows <= kWmmaWarps, "one warp per query in the scans");
    const int max_visible = base_pos + Scratch::kQueryRows;
    const int chunks = (max_visible + kTopKChunk - 1) / kTopKChunk;
    const int items = Scratch::kQueryRows * chunks;
    const int scan_chunks = (max_visible + kTopKScanChunk - 1) / kTopKScanChunk;
    const int scan_items = Scratch::kQueryRows * scan_chunks;
    if (max_visible <= kTopKLocalMaxVisible) {
      // One CTA per query selects in shared memory; one grid barrier instead of 4-7.
      if (int(blockIdx.x) < Scratch::kQueryRows) {
        select_per_query_topk_local(logits, selections, int(blockIdx.x),
                                    base_pos + int(blockIdx.x) + 1, shared_words);
      }
      record_phase(attention_temp, 7);
      grid.sync();
      record_phase(attention_temp, 10);
      return;
    }
    if (tid < Scratch::kQueryRows) {
      prefix[tid] = 0u;
      wanted[tid] = unsigned(Scratch::kIndexTopK);
    }
    __syncthreads();

    // Passes 0 and 1: the two high digits, per-CTA shared histograms merged once per pass.
#pragma unroll 1
    for (int pass = 0; pass < 2; ++pass) {
      const int shift = 24 - 8 * pass;
      topk_grid_digit_pass(logits, grid_base, base_pos, scan_chunks, scan_items, pass, prefix,
                           shared_hist);
      grid.sync();
      record_phase(attention_temp, 4 + pass);
      if (warp < Scratch::kQueryRows) {
        topk_grid_find_bin_warp(topk_grid_hist(grid_base, warp, pass), wanted[warp], lane,
                                bin_out + 2 * warp);
      }
      __syncthreads();
      if (tid < Scratch::kQueryRows) {
        prefix[tid] |= bin_out[2 * tid] << unsigned(shift);
        wanted[tid] = bin_out[2 * tid + 1];
      }
      __syncthreads();
    }
    if (max_visible < kTopKCompactMinVisible) {
      topk_grid_full_finish(logits, selections, grid_base, base_pos, chunks, items, scan_chunks,
                            scan_items, attention_temp, shared_words, shared_hist);
      return;
    }
    // Compaction: per query, the tokens above the 16-bit prefix and the candidates equal to it.
    for (int item = int(blockIdx.x); item < scan_items; item += int(gridDim.x)) {
      const int query = item / scan_chunks;
      const int chunk = item - query * scan_chunks;
      const int token0 = chunk * kTopKScanChunk + tid * kTopKVec;
      const int visible = base_pos + query + 1;
      const unsigned prefix16 = prefix[query];
      const float4 v = topk_grid_load4(logits, query, token0, visible);
      const float vals[kTopKVec] = {v.x, v.y, v.z, v.w};
      unsigned* counters = topk_grid_counters(grid_base, query);
      unsigned key[kTopKVec];
      bool above[kTopKVec];
      bool equal[kTopKVec];
      bool any = false;
#pragma unroll
      for (int j = 0; j < kTopKVec; ++j) {
        key[j] = 0u;
        above[j] = false;
        equal[j] = false;
        if (token0 + j < visible) {
          key[j] = ordered_float_key(vals[j]);
          above[j] = (key[j] & 0xffff0000u) > prefix16;
          equal[j] = (key[j] & 0xffff0000u) == prefix16;
        }
        any |= above[j] | equal[j];
      }
      // Flagged tokens are ~0.2 % of the keys: one ballot skips the appends for most warp steps.
      if (__ballot_sync(0xffffffffu, any) != 0u) {
#pragma unroll
        for (int j = 0; j < kTopKVec; ++j) {
          topk_grid_append_warp(above[j], unsigned(token0 + j), key[j], counters,
                                topk_grid_above(grid_base, query), nullptr,
                                unsigned(kTopKAboveWords), lane);
          topk_grid_append_warp(equal[j], unsigned(token0 + j), key[j], counters + 1,
                                topk_grid_candidate_token(grid_base, query),
                                topk_grid_candidate_key(grid_base, query),
                                unsigned(kTopKCandidateCap), lane);
        }
      }
    }
    grid.sync();
    record_phase(attention_temp, 6);
    // Every CTA reads the counters: the finish is chosen uniformly across the grid.
    unsigned overflow = 0u;
    for (int query = 0; query < Scratch::kQueryRows; ++query) {
      overflow |= topk_grid_counters(grid_base, query)[1] > unsigned(kTopKCandidateCap) ? 1u : 0u;
    }
    if (overflow == 0u) {
      if (int(blockIdx.x) < Scratch::kQueryRows) {
        const int query = int(blockIdx.x);
        topk_grid_query_finish(selections, grid_base, query, prefix[query], wanted[query],
                               shared_words, shared_hist, sort_storage);
      }
      record_phase(attention_temp, 7);
      grid.sync();
      record_phase(attention_temp, 10);
      return;
    }
    topk_grid_full_finish(logits, selections, grid_base, base_pos, chunks, items, scan_chunks,
                          scan_items, attention_temp, shared_words, shared_hist);
  }
