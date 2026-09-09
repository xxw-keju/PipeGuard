# Normalized device code for PipeGuard Suite 3.
# Exact upstream code and provenance are stored beside this file.

from typing import Callable, Optional, Tuple
import tilelang.language as T
import tilelang

def _make_apply_mask(is_causal, has_window, window_size_left, window_size_right, accum_dtype, block_m, block_n):
    """Create a masked attention score initialization macro.

    All parameters are compile-time constants baked into the macro via closure.
    The macro writes 0 or ``-infinity`` into ``acc_s`` depending on the mask
    conditions, using four compile-time paths:

    - causal + window (left only)
    - causal only
    - window only (left and/or right)
    - no masking (OOB guard only)

    Args:
        is_causal: Whether causal masking is applied.
        has_window: Whether any window constraint is active.
        window_size_left: Left window size (-1 = unlimited).
        window_size_right: Right window size (-1 = unlimited).
        accum_dtype: Accumulator data type string (e.g. "float").
        block_m: Tile size along the Q dimension.
        block_n: Tile size along the KV dimension.

    Returns:
        apply_mask: A ``T.macro`` that fills ``acc_s`` with mask values.
    """

    @T.macro
    def apply_mask(acc_s, k_idx, bx, q_len, kv_len, offset):
        if is_causal and has_window:
            for i, j in T.Parallel(block_m, block_n):
                causal_mask = k_idx * block_n + j > bx * block_m + i + offset
                left_mask = window_size_left >= 0 and k_idx * block_n + j < bx * block_m + i + offset - window_size_left
                q_oob = bx * block_m + i >= q_len
                k_oob = k_idx * block_n + j >= kv_len
                acc_s[i, j] = T.if_then_else(causal_mask or left_mask or q_oob or k_oob, -T.infinity(accum_dtype), 0)
        elif is_causal:
            for i, j in T.Parallel(block_m, block_n):
                causal_mask = k_idx * block_n + j > bx * block_m + i + offset
                q_oob = bx * block_m + i >= q_len
                k_oob = k_idx * block_n + j >= kv_len
                acc_s[i, j] = T.if_then_else(causal_mask or q_oob or k_oob, -T.infinity(accum_dtype), 0)
        elif has_window:
            for i, j in T.Parallel(block_m, block_n):
                left_mask = window_size_left >= 0 and k_idx * block_n + j < bx * block_m + i + offset - window_size_left
                right_mask = window_size_right >= 0 and k_idx * block_n + j > bx * block_m + i + offset + window_size_right
                q_oob = bx * block_m + i >= q_len
                k_oob = k_idx * block_n + j >= kv_len
                acc_s[i, j] = T.if_then_else(left_mask or right_mask or q_oob or k_oob, -T.infinity(accum_dtype), 0)
        else:
            for i, j in T.Parallel(block_m, block_n):
                q_oob = bx * block_m + i >= q_len
                k_oob = k_idx * block_n + j >= kv_len
                acc_s[i, j] = T.if_then_else(q_oob or k_oob, -T.infinity(accum_dtype), 0)
    return apply_mask
LOG2E: float = 1.4426950408889634

def make_log2e_scale(dim):
    """Compute softmax scale with log2(e) factor pre-multiplied.

    Returns (1/sqrt(dim)) * log2(e) for use with exp2-based softmax.
    """
    return (1.0 / dim) ** 0.5 * LOG2E

def make_online_softmax_with_mask_guard(scale, accum_dtype, block_rows, block_cols):
    """Create an online softmax T.macro with monotonic max enforcement and NaN guard.

    Use this variant instead of ``make_online_softmax`` when some attention blocks
    may be fully masked (all scores = -infinity), e.g., causal or sliding-window
    attention with OOB guards.  Two extra steps vs the base variant:

    * **Monotonic max**: ``scores_max[i] = max(scores_max[i], scores_max_prev[i])``
      ensures the running maximum never decreases when the current block's max
      is smaller than the accumulated maximum.
    * **NaN guard**: clamps ``scores_max[i]`` to at least ``-1e38`` so that
      ``exp2(-inf - (-inf))`` never produces NaN for fully-masked blocks.

    Note: These extra T.Parallel loops may conflict with WGMMA pipeline stage
    constraints in some kernels — always verify with tests after adopting.

    Args:
        scale: Pre-computed scale factor (should include LOG2E multiplication)
        accum_dtype: Accumulator data type (e.g., "float")
        block_rows: Number of rows in the score matrix
        block_cols: Number of columns in the score matrix

    Returns:
        online_softmax: A T.macro that performs the online softmax update
    """

    @T.macro
    def online_softmax(acc_s, scores_max, scores_max_prev, scores_scale, scores_sum, logsum):
        T.copy(scores_max, scores_max_prev)
        T.fill(scores_max, -T.infinity(accum_dtype))
        T.reduce_max(acc_s, scores_max, dim=1, clear=False)
        for i in T.Parallel(block_rows):
            scores_max[i] = T.max(scores_max[i], scores_max_prev[i])
        for i in T.Parallel(block_rows):
            scores_max[i] = T.max(scores_max[i], T.cast(-1e+38, accum_dtype))
        for i in T.Parallel(block_rows):
            scores_scale[i] = T.exp2(scores_max_prev[i] * scale - scores_max[i] * scale)
        for i, j in T.Parallel(block_rows, block_cols):
            acc_s[i, j] = T.exp2(acc_s[i, j] * scale - scores_max[i] * scale)
        T.reduce_sum(acc_s, scores_sum, dim=1)
        for i in T.Parallel(block_rows):
            logsum[i] = logsum[i] * scores_scale[i] + scores_sum[i]
    return online_softmax

def make_rescale(block_rows, head_dim):
    """Create a reusable rescale T.macro for the output accumulator.

    Args:
        block_rows: Number of rows in the output accumulator
        head_dim: Dimension of each head

    Returns:
        rescale: A T.macro that rescales acc_o by scores_scale
    """

    @T.macro
    def rescale(acc_o, scores_scale):
        for i, j in T.Parallel(block_rows, head_dim):
            acc_o[i, j] *= scores_scale[i]
    return rescale

def _kernel_factory(batch: int, heads: int, heads_kv: int, total_q: int, total_k: int, dim: int, is_causal: bool, window_size_left: int, window_size_right: int, dtype: str='float16', accum_dtype: str='float') -> Callable:
    scale = make_log2e_scale(dim)
    if heads % heads_kv != 0:
        raise ValueError('heads must be divisible by heads_kv')
    groups = heads // heads_kv
    has_window = window_size_left >= 0 or window_size_right >= 0

    @tilelang.jit(out_idx=[6, 7], pass_configs={tilelang.PassConfigKey.TL_ENABLE_FAST_MATH: True}, compile_flags=['-O3', '-DENABLE_BF16'])
    def _gqa_sw_fwd_varlen_wgmma_pipelined_func(block_m, block_n, num_stages, threads):
        q_shape = (total_q, heads, dim)
        kv_shape = (total_k, heads_kv, dim)
        apply_mask = _make_apply_mask(is_causal, has_window, window_size_left, window_size_right, accum_dtype, block_m, block_n)
        online_softmax = make_online_softmax_with_mask_guard(scale, accum_dtype, block_m, block_n)
        rescale = make_rescale(block_m, dim)

        @T.macro
        def mma0(k: T.Tensor(kv_shape, dtype), q_shared: T.SharedBuffer([block_m, dim], dtype), k_shared: T.SharedBuffer([block_n, dim], dtype), acc_s: T.FragmentBuffer([block_m, block_n], accum_dtype), k_idx: T.int32, bx: T.int32, by: T.int32, kv_start: T.int32, q_len: T.int32, kv_len: T.int32, offset: T.int32) -> None:
            T.copy(k[kv_start + k_idx * block_n:kv_start + (k_idx + 1) * block_n, by // groups, :], k_shared)
            apply_mask(acc_s, k_idx, bx, q_len, kv_len, offset)
            T.gemm(q_shared, k_shared, acc_s, transpose_B=True, policy=T.GemmWarpPolicy.FullRow)

        @T.macro
        def mma1(v: T.Tensor(kv_shape, dtype), v_shared: T.SharedBuffer([block_n, dim], dtype), acc_s_cast: T.FragmentBuffer([block_m, block_n], dtype), acc_o: T.FragmentBuffer([block_m, dim], accum_dtype), k_idx: T.int32, by: T.int32, kv_start: T.int32) -> None:
            T.copy(v[kv_start + k_idx * block_n:kv_start + (k_idx + 1) * block_n, by // groups, :], v_shared)
            T.gemm(acc_s_cast, v_shared, acc_o, policy=T.GemmWarpPolicy.FullRow)

        @T.prim_func
        def _gqa_sw_fwd_varlen_wgmma_pipelined_main(q: T.Tensor(q_shape, dtype), k: T.Tensor(kv_shape, dtype), v: T.Tensor(kv_shape, dtype), cu_seqlens_q: T.Tensor([batch + 1], T.int32), cu_seqlens_k: T.Tensor([batch + 1], T.int32), max_seqlen_q: T.int32, output: T.Tensor(q_shape, dtype), lse: T.Tensor([heads, total_q], accum_dtype)) -> None:
            with T.Kernel(T.ceildiv(max_seqlen_q, block_m), heads, batch, threads=threads) as (bx, by, bz):
                q_shared = T.alloc_shared([block_m, dim], dtype)
                k_shared = T.alloc_shared([block_n, dim], dtype)
                v_shared = T.alloc_shared([block_n, dim], dtype)
                o_shared = T.alloc_shared([block_m, dim], dtype)
                acc_s = T.alloc_fragment([block_m, block_n], accum_dtype)
                acc_s_cast = T.alloc_fragment([block_m, block_n], dtype)
                acc_o = T.alloc_fragment([block_m, dim], accum_dtype)
                scores_max = T.alloc_fragment([block_m], accum_dtype)
                scores_max_prev = T.alloc_fragment([block_m], accum_dtype)
                scores_scale = T.alloc_fragment([block_m], accum_dtype)
                scores_sum = T.alloc_fragment([block_m], accum_dtype)
                logsum = T.alloc_fragment([block_m], accum_dtype)
                T.annotate_layout({o_shared: tilelang.layout.make_swizzled_layout(o_shared)})
                q_start = cu_seqlens_q[bz]
                kv_start = cu_seqlens_k[bz]
                q_len = cu_seqlens_q[bz + 1] - q_start
                kv_len = cu_seqlens_k[bz + 1] - kv_start
                offset = kv_len - q_len
                T.copy(q[q_start + bx * block_m:q_start + (bx + 1) * block_m, by, :], q_shared)
                T.clear(acc_o)
                T.clear(logsum)
                T.fill(scores_max, -T.infinity(accum_dtype))
                if is_causal:
                    k_end = T.ceildiv(T.min(kv_len, offset + (bx + 1) * block_m), block_n)
                elif has_window and window_size_right >= 0:
                    k_end = T.ceildiv(T.min(kv_len, offset + (bx + 1) * block_m + window_size_right), block_n)
                else:
                    k_end = T.ceildiv(kv_len, block_n)
                if has_window and window_size_left >= 0:
                    k_start = T.max(0, offset + bx * block_m - window_size_left) // block_n
                else:
                    k_start = 0
                loop_count = T.max(k_end - k_start, 0)
                for k_offset in T.Pipelined(loop_count, num_stages=num_stages):
                    k_idx = k_start + k_offset
                    mma0(k, q_shared, k_shared, acc_s, k_idx, bx, by, kv_start, q_len, kv_len, offset)
                    online_softmax(acc_s, scores_max, scores_max_prev, scores_scale, scores_sum, logsum)
                    T.copy(acc_s, acc_s_cast)
                    rescale(acc_o, scores_scale)
                    mma1(v, v_shared, acc_s_cast, acc_o, k_idx, by, kv_start)
                for i, j in T.Parallel(block_m, dim):
                    acc_o[i, j] = T.if_then_else(logsum[i] > 0, acc_o[i, j] / logsum[i], 0.0)
                T.sync_threads(3, threads)
                T.copy(acc_o, o_shared)
                T.sync_threads(3, threads)
                for i, j in T.Parallel(block_m, dim):
                    if bx * block_m + i < q_len:
                        output[q_start + bx * block_m + i, by, j] = o_shared[i, j]
                for i in T.Parallel(block_m):
                    if bx * block_m + i < q_len:
                        logsum[i] = T.log2(logsum[i]) + scores_max[i] * scale
                        lse[by, q_start + bx * block_m + i] = logsum[i]
        return _gqa_sw_fwd_varlen_wgmma_pipelined_main
    return _gqa_sw_fwd_varlen_wgmma_pipelined_func

def build_kernel(case):
    """Construct the TileLang device entry without launching it."""
    return _kernel_factory(**case['build']['factory_arguments'])
