# Normalized device code for PipeGuard Suite 3.
# Exact upstream code and provenance are stored beside this file.

from typing import Callable, Optional
import tilelang.language as T
import math
import tilelang

def _kernel_factory(batch: int, n_heads: int, d_head: int, d_state: int, n_groups: int, dtype: str='float16') -> Callable:
    accum_dtype = 'float'
    B = batch
    H = n_heads
    P = d_head
    N = d_state
    G = n_groups
    assert H % G == 0, f'n_heads ({H}) must be divisible by n_groups ({G})'
    HEADS_PER_GROUP = H // G

    @tilelang.jit(out_idx=[-1])
    def kernel_func(block_p: int, block_n: int, threads: int):
        if not (block_n > 0 and block_n & block_n - 1 == 0):
            raise ValueError(f'block_n must be a power of 2 for the log-depth tree reduction; got {block_n}')
        _log_n = int(math.log2(block_n))

        @T.prim_func
        def main(A: T.Tensor((H, P, N), accum_dtype), dt: T.Tensor((B, H, P), accum_dtype), x: T.Tensor((B, H, P), dtype), B_in: T.Tensor((B, G, N), dtype), C_in: T.Tensor((B, G, N), dtype), state: T.Tensor((B, H, P, N), accum_dtype), y_out: T.Tensor((B, H, P), accum_dtype)):
            with T.Kernel(B * H, T.ceildiv(P, block_p), threads=threads) as (bh, bp):
                b = bh // H
                h = bh % H
                g = h // HEADS_PER_GROUP
                p0 = bp * block_p
                y_frag = T.alloc_fragment((block_p, block_n), accum_dtype)
                T.clear(y_frag)
                x_frag = T.alloc_fragment((block_p,), accum_dtype)
                dt_frag = T.alloc_fragment((block_p,), accum_dtype)
                for pp in T.Parallel(block_p):
                    p_idx = p0 + pp
                    valid_p = p_idx < P
                    x_frag[pp] = T.if_then_else(valid_p, T.cast(x[b, h, p_idx], accum_dtype), T.float32(0.0))
                    dt_frag[pp] = T.if_then_else(valid_p, dt[b, h, p_idx], T.float32(0.0))
                for n_blk in T.serial(T.ceildiv(N, block_n)):
                    n0 = n_blk * block_n
                    for pp, nn in T.Parallel(block_p, block_n):
                        p_idx = p0 + pp
                        n_idx = n0 + nn
                        valid = p_idx < P and n_idx < N
                        A_val = T.if_then_else(valid, A[h, p_idx, n_idx], T.float32(0.0))
                        B_val = T.if_then_else(valid, T.cast(B_in[b, g, n_idx], accum_dtype), T.float32(0.0))
                        C_val = T.if_then_else(valid, T.cast(C_in[b, g, n_idx], accum_dtype), T.float32(0.0))
                        old_s = T.if_then_else(valid, state[b, h, p_idx, n_idx], T.float32(0.0))
                        dA_val = T.exp(dt_frag[pp] * A_val)
                        new_s = dA_val * old_s + dt_frag[pp] * x_frag[pp] * B_val
                        if valid:
                            state[b, h, p_idx, n_idx] = new_s
                        y_frag[pp, nn] = y_frag[pp, nn] + new_s * C_val
                y_smem = T.alloc_shared((block_p, block_n), accum_dtype)
                for pp, nn in T.Parallel(block_p, block_n):
                    y_smem[pp, nn] = y_frag[pp, nn]
                T.sync_threads()
                for _d in range(_log_n):
                    _stride = block_n >> _d + 1
                    for pp, nn in T.Parallel(block_p, block_n):
                        if nn < _stride:
                            y_smem[pp, nn] = y_smem[pp, nn] + y_smem[pp, nn + _stride]
                    T.sync_threads()
                for pp, nn in T.Parallel(block_p, block_n):
                    if nn == 0:
                        p_idx = p0 + pp
                        if p_idx < P:
                            y_out[b, h, p_idx] = y_smem[pp, 0]
        return main
    return kernel_func

def build_kernel(case):
    """Construct the TileLang device entry without launching it."""
    return _kernel_factory(**case['build']['factory_arguments'])
