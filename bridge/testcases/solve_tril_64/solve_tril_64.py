# Copyright (c) 2023-2026, Songlin Yang, Yu Zhang, Zhiyuan Li
#
# This source code is licensed under the MIT license found in the
# LICENSE file in the root directory of this source tree.
# For a list of all contributors, visit:
#   https://github.com/fla-org/flash-linear-attention/graphs/contributors

"""Standalone original solve_tril.py 64x64 merge kernel.

Source: Q2TritonKernel/src/kernels/fla/ops/utils/solve_tril.py:135.
Benchmark: Q2TritonKernel/tests/fla_perf/test_solve_tril_perf.py.
The complete kernel body and do_not_specialize=['T'] are preserved.
Host FLA imports/input_guard/IS_VARLEN heuristic are replaced by explicit args.
Default B=1,T=1024,H=32,BT=64,FP32 matches the fixed-length capture recipe;
num_warps=2 is the capture harness choice, not a measured autotuner winner.
Use --sequence-lengths for a packed varlen specialization, or --length 64
--heads 2 for a smaller simulator run. Native NPU-IR is the default.
Inputs/reference/zero output initialization run on CPU before transfer.
A fresh AVE dump is required to reconfirm predicate UB stores/reloads.
"""

import argparse
import os

import torch
import torch.nn.functional as F
import triton
import triton.language as tl


@triton.jit(do_not_specialize=['T'])
def merge_16x16_to_64x64_inverse_kernel(
    A,
    Ai,
    cu_seqlens,
    chunk_indices,
    T,
    H: tl.constexpr,
    BT: tl.constexpr,
    USE_TMA: tl.constexpr,
    IS_VARLEN: tl.constexpr,
    DOT_PRECISION: tl.constexpr,
):
    i_t, i_bh = tl.program_id(0), tl.program_id(1)
    i_b, i_h = i_bh // H, i_bh % H
    if IS_VARLEN:
        i_n, i_t = tl.load(chunk_indices + i_t * 2).to(tl.int32), tl.load(chunk_indices + i_t * 2 + 1).to(tl.int32)
        bos, eos = tl.load(cu_seqlens + i_n).to(tl.int32), tl.load(cu_seqlens + i_n + 1).to(tl.int32)
        T = eos - bos
    else:
        bos, eos = i_b * T, i_b * T + T

    o_i = tl.arange(0, 16)
    m_A = o_i[:, None] > o_i[None, :]
    m_I = o_i[:, None] == o_i[None, :]
    A += (bos * H + i_h) * BT
    Ai += (bos * H + i_h) * BT

    p_A_11 = tl.make_block_ptr(A, (T, BT), (H*BT, 1), (i_t * BT, 0), (16, 16), (1, 0))
    p_A_22 = tl.make_block_ptr(A, (T, BT), (H*BT, 1), (i_t * BT + 16, 16), (16, 16), (1, 0))
    p_A_33 = tl.make_block_ptr(A, (T, BT), (H*BT, 1), (i_t * BT + 32, 32), (16, 16), (1, 0))
    p_A_44 = tl.make_block_ptr(A, (T, BT), (H*BT, 1), (i_t * BT + 48, 48), (16, 16), (1, 0))
    b_Ai_11 = tl.load(p_A_11, boundary_check=(0, 1)).to(tl.float32)
    b_Ai_22 = tl.load(p_A_22, boundary_check=(0, 1)).to(tl.float32)
    b_Ai_33 = tl.load(p_A_33, boundary_check=(0, 1)).to(tl.float32)
    b_Ai_44 = tl.load(p_A_44, boundary_check=(0, 1)).to(tl.float32)

    # [16, 16]
    b_Ai_11 = -tl.where(m_A, b_Ai_11, 0)
    b_Ai_22 = -tl.where(m_A, b_Ai_22, 0)
    b_Ai_33 = -tl.where(m_A, b_Ai_33, 0)
    b_Ai_44 = -tl.where(m_A, b_Ai_44, 0)

    for i in range(2, min(16, T - i_t * BT)):
        b_a_11 = -tl.load(A + (i_t * BT + i) * H*BT + o_i)
        b_a_11 = tl.where(o_i < i, b_a_11, 0.)
        b_a_11 += tl.sum(b_a_11[:, None] * b_Ai_11, 0)
        b_Ai_11 = tl.where((o_i == i)[:, None], b_a_11, b_Ai_11)
    for i in range(16 + 2, min(32, T - i_t * BT)):
        b_a_22 = -tl.load(A + (i_t * BT + i) * H*BT + o_i + 16)
        b_a_22 = tl.where(o_i < i - 16, b_a_22, 0.)
        b_a_22 += tl.sum(b_a_22[:, None] * b_Ai_22, 0)
        b_Ai_22 = tl.where((o_i == i - 16)[:, None], b_a_22, b_Ai_22)
    for i in range(32 + 2, min(48, T - i_t * BT)):
        b_a_33 = -tl.load(A + (i_t * BT + i) * H*BT + o_i + 32)
        b_a_33 = tl.where(o_i < i - 32, b_a_33, 0.)
        b_a_33 += tl.sum(b_a_33[:, None] * b_Ai_33, 0)
        b_Ai_33 = tl.where((o_i == i - 32)[:, None], b_a_33, b_Ai_33)
    for i in range(48 + 2, min(64, T - i_t * BT)):
        b_a_44 = -tl.load(A + (i_t * BT + i) * H*BT + o_i + 48)
        b_a_44 = tl.where(o_i < i - 48, b_a_44, 0.)
        b_a_44 += tl.sum(b_a_44[:, None] * b_Ai_44, 0)
        b_Ai_44 = tl.where((o_i == i - 48)[:, None], b_a_44, b_Ai_44)
    b_Ai_11 += m_I
    b_Ai_22 += m_I
    b_Ai_33 += m_I
    b_Ai_44 += m_I

    p_A_21 = tl.make_block_ptr(A, (T, BT), (H*BT, 1), (i_t * BT + 16, 0), (16, 16), (1, 0))
    p_A_31 = tl.make_block_ptr(A, (T, BT), (H*BT, 1), (i_t * BT + 32, 0), (16, 16), (1, 0))
    p_A_32 = tl.make_block_ptr(A, (T, BT), (H*BT, 1), (i_t * BT + 32, 16), (16, 16), (1, 0))
    p_A_41 = tl.make_block_ptr(A, (T, BT), (H*BT, 1), (i_t * BT + 48, 0), (16, 16), (1, 0))
    p_A_42 = tl.make_block_ptr(A, (T, BT), (H*BT, 1), (i_t * BT + 48, 16), (16, 16), (1, 0))
    p_A_43 = tl.make_block_ptr(A, (T, BT), (H*BT, 1), (i_t * BT + 48, 32), (16, 16), (1, 0))
    b_A_21 = tl.load(p_A_21, boundary_check=(0, 1)).to(tl.float32)
    b_A_31 = tl.load(p_A_31, boundary_check=(0, 1)).to(tl.float32)
    b_A_32 = tl.load(p_A_32, boundary_check=(0, 1)).to(tl.float32)
    b_A_41 = tl.load(p_A_41, boundary_check=(0, 1)).to(tl.float32)
    b_A_42 = tl.load(p_A_42, boundary_check=(0, 1)).to(tl.float32)
    b_A_43 = tl.load(p_A_43, boundary_check=(0, 1)).to(tl.float32)

    b_Ai_21 = -tl.dot(tl.dot(b_Ai_22, b_A_21, input_precision=DOT_PRECISION), b_Ai_11, input_precision=DOT_PRECISION)
    b_Ai_32 = -tl.dot(tl.dot(b_Ai_33, b_A_32, input_precision=DOT_PRECISION), b_Ai_22, input_precision=DOT_PRECISION)
    b_Ai_43 = -tl.dot(tl.dot(b_Ai_44, b_A_43, input_precision=DOT_PRECISION), b_Ai_33, input_precision=DOT_PRECISION)

    b_Ai_31 = -tl.dot(
        b_Ai_33,
        tl.dot(b_A_31, b_Ai_11, input_precision=DOT_PRECISION) +
        tl.dot(b_A_32, b_Ai_21, input_precision=DOT_PRECISION),
        input_precision=DOT_PRECISION,
    )
    b_Ai_42 = -tl.dot(
        b_Ai_44,
        tl.dot(b_A_42, b_Ai_22, input_precision=DOT_PRECISION) +
        tl.dot(b_A_43, b_Ai_32, input_precision=DOT_PRECISION),
        input_precision=DOT_PRECISION,
    )
    b_Ai_41 = -tl.dot(
        b_Ai_44,
        tl.dot(b_A_41, b_Ai_11, input_precision=DOT_PRECISION) +
        tl.dot(b_A_42, b_Ai_21, input_precision=DOT_PRECISION) +
        tl.dot(b_A_43, b_Ai_31, input_precision=DOT_PRECISION),
        input_precision=DOT_PRECISION,
    )

    p_Ai_11 = tl.make_block_ptr(Ai, (T, BT), (H*BT, 1), (i_t * BT, 0), (16, 16), (1, 0))
    p_Ai_22 = tl.make_block_ptr(Ai, (T, BT), (H*BT, 1), (i_t * BT + 16, 16), (16, 16), (1, 0))
    p_Ai_33 = tl.make_block_ptr(Ai, (T, BT), (H*BT, 1), (i_t * BT + 32, 32), (16, 16), (1, 0))
    p_Ai_44 = tl.make_block_ptr(Ai, (T, BT), (H*BT, 1), (i_t * BT + 48, 48), (16, 16), (1, 0))
    p_Ai_21 = tl.make_block_ptr(Ai, (T, BT), (H*BT, 1), (i_t * BT + 16, 0), (16, 16), (1, 0))
    p_Ai_31 = tl.make_block_ptr(Ai, (T, BT), (H*BT, 1), (i_t * BT + 32, 0), (16, 16), (1, 0))
    p_Ai_32 = tl.make_block_ptr(Ai, (T, BT), (H*BT, 1), (i_t * BT + 32, 16), (16, 16), (1, 0))
    p_Ai_41 = tl.make_block_ptr(Ai, (T, BT), (H*BT, 1), (i_t * BT + 48, 0), (16, 16), (1, 0))
    p_Ai_42 = tl.make_block_ptr(Ai, (T, BT), (H*BT, 1), (i_t * BT + 48, 16), (16, 16), (1, 0))
    p_Ai_43 = tl.make_block_ptr(Ai, (T, BT), (H*BT, 1), (i_t * BT + 48, 32), (16, 16), (1, 0))
    tl.store(p_Ai_11, b_Ai_11.to(p_Ai_11.dtype.element_ty, fp_downcast_rounding="rtne"), boundary_check=(0, 1))
    tl.store(p_Ai_22, b_Ai_22.to(p_Ai_22.dtype.element_ty, fp_downcast_rounding="rtne"), boundary_check=(0, 1))
    tl.store(p_Ai_33, b_Ai_33.to(p_Ai_33.dtype.element_ty, fp_downcast_rounding="rtne"), boundary_check=(0, 1))
    tl.store(p_Ai_44, b_Ai_44.to(p_Ai_44.dtype.element_ty, fp_downcast_rounding="rtne"), boundary_check=(0, 1))
    tl.store(p_Ai_21, b_Ai_21.to(p_Ai_21.dtype.element_ty, fp_downcast_rounding="rtne"), boundary_check=(0, 1))
    tl.store(p_Ai_31, b_Ai_31.to(p_Ai_31.dtype.element_ty, fp_downcast_rounding="rtne"), boundary_check=(0, 1))
    tl.store(p_Ai_32, b_Ai_32.to(p_Ai_32.dtype.element_ty, fp_downcast_rounding="rtne"), boundary_check=(0, 1))
    tl.store(p_Ai_41, b_Ai_41.to(p_Ai_41.dtype.element_ty, fp_downcast_rounding="rtne"), boundary_check=(0, 1))
    tl.store(p_Ai_42, b_Ai_42.to(p_Ai_42.dtype.element_ty, fp_downcast_rounding="rtne"), boundary_check=(0, 1))
    tl.store(p_Ai_43, b_Ai_43.to(p_Ai_43.dtype.element_ty, fp_downcast_rounding="rtne"), boundary_check=(0, 1))


def make_inputs(batch, length, heads, sequence_lengths=None):
    """Normalized-key Gram matrices, as in the original solve benchmark."""
    torch.manual_seed(42)
    lengths = sequence_lengths if sequence_lengths else [length] * batch
    A = torch.zeros((batch, length, heads, 64), dtype=torch.float32)
    chunks = []
    bos = 0
    for seq, seq_length in enumerate(lengths):
        b = 0 if sequence_lengths else seq
        begin = bos if sequence_lengths else 0
        for chunk in range(triton.cdiv(seq_length, 64)):
            start = begin + chunk * 64
            count = min(64, seq_length - chunk * 64)
            keys = F.normalize(torch.randn(heads, count, 64), dim=-1)
            lower = (keys @ keys.transpose(-1, -2)).tril(-1)
            A[b, start:start + count, :, :count] = lower.permute(1, 0, 2)
            chunks.append((seq, chunk, b, start, count))
        bos += seq_length
    return A, chunks


def reference(A, chunks):
    """Independently solve (I + A) X = I in CPU float64 per chunk/head."""
    result = torch.zeros_like(A)
    for _, _, b, start, count in chunks:
        lower = A[b, start:start + count, :, :count].permute(1, 0, 2).double()
        eye = torch.eye(count, dtype=torch.float64).expand(A.shape[2], -1, -1)
        inverse = torch.linalg.solve_triangular(eye + lower, eye, upper=False)
        result[b, start:start + count, :, :count] = inverse.permute(1, 0, 2).float()
    return result


def main():
    parser = argparse.ArgumentParser(description=__doc__)
    parser.add_argument('--batch', type=int, default=1)
    parser.add_argument('--length', type=int, default=1024)
    parser.add_argument('--heads', type=int, default=32)
    parser.add_argument('--sequence-lengths', type=int, nargs='+',
                        help='Packed variable-length sequences; requires batch=1; overrides length')
    parser.add_argument('--compile-flow', choices=('npuir', 'ptoas'), default='npuir')
    args = parser.parse_args()
    if min(args.batch, args.length, args.heads) < 1:
        parser.error('batch, length and heads must be positive')
    if args.sequence_lengths:
        if args.batch != 1 or min(args.sequence_lengths) < 1:
            parser.error('packed sequences require batch=1 and positive sequence lengths')
        args.length = sum(args.sequence_lengths)
    elif args.length % 64:
        parser.error('fixed length must be a multiple of 64; use --sequence-lengths for tails')

    os.environ['TRITON_ASCEND_COMPILE_FLOW'] = args.compile_flow
    if args.compile_flow == 'npuir':
        os.environ.pop('BISHENGIR_ENABLE_PTOAS_BRIDGE', None)
        os.environ.pop('BISHENGIR_PTOAS_BRIDGE_MODE', None)
    else:
        os.environ['BISHENGIR_ENABLE_PTOAS_BRIDGE'] = '1'
        os.environ['BISHENGIR_PTOAS_BRIDGE_MODE'] = 'ptodsl'
    os.environ['TRITON_F32_DEFAULT'] = 'ieee'

    import torch_npu  # Registers the real or simulated NPU runtime.
    if not torch.npu.is_available():
        raise RuntimeError('Run on an NPU or under the configured CANN msprof op simulator')

    A_cpu, chunks = make_inputs(args.batch, args.length, args.heads, args.sequence_lengths)
    expected = reference(A_cpu, chunks)
    # The original wrapper zeros Ai: upper off-diagonal tiles are never written.
    A = A_cpu.npu()
    output = torch.zeros_like(A_cpu).npu()
    cu_seqlens = chunk_indices = None
    if args.sequence_lengths:
        cu_cpu = torch.tensor([0] + args.sequence_lengths, dtype=torch.int32).cumsum(0).to(torch.int32)
        indices_cpu = torch.tensor([(seq, chunk) for seq, chunk, _, _, _ in chunks], dtype=torch.int32)
        cu_seqlens, chunk_indices = cu_cpu.npu(), indices_cpu.npu()
    grid = (len(chunks), args.heads) if args.sequence_lengths else (
        triton.cdiv(args.length, 64), args.batch * args.heads)
    print(f'flow={args.compile_flow}, B={args.batch}, T={args.length}, H={args.heads}, '
          f'BT=64, IS_VARLEN={bool(args.sequence_lengths)}, grid={grid}, '
          'num_warps=2, num_stages=2, DOT_PRECISION=ieee', flush=True)
    merge_16x16_to_64x64_inverse_kernel[grid](
        A=A, Ai=output, cu_seqlens=cu_seqlens, chunk_indices=chunk_indices,
        T=args.length, H=args.heads, BT=64, USE_TMA=False,
        IS_VARLEN=bool(args.sequence_lengths), DOT_PRECISION='ieee',
        num_warps=2, num_stages=2, debug=True, compile_flow=args.compile_flow,
        sync_solver=True, multibuffer=True,
        limit_auto_multi_buffer_of_local_buffer='no-limit',
    )
    torch.npu.synchronize()
    actual = output.cpu()
    # Explicit elementwise tolerances, distinct from FLA's assert_close metric.
    torch.testing.assert_close(actual, expected, atol=1e-4, rtol=1e-4)
    print(f'PASS: all output entries compared; max absolute error='
          f'{(actual - expected).abs().max().item():.8g}', flush=True)


if __name__ == '__main__':
    main()
