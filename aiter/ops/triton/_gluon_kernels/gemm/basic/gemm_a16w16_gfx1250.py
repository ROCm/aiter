# SPDX-License-Identifier: MIT
# Copyright (C) 2026, Advanced Micro Devices, Inc. All rights reserved.

import torch
import triton
import math
from typing import Optional, Dict
from triton.experimental import gluon
import triton.experimental.gluon.language as gl
from aiter.ops.triton._triton_kernels.activation import _get_activation_from_str
from aiter.ops.triton.utils.gemm_config_utils import get_gemm_config
from aiter.ops.triton.utils.logger import AiterTritonLogger
from aiter.ops.triton.utils._triton.kernel_repr import make_kernel_repr

_LOGGER = AiterTritonLogger()

_GLUON_REPR_KEYS = [
    "BLOCK_M",
    "BLOCK_N",
    "BLOCK_K",
    "NUM_BUFFERS",
    "PHYSICAL_MK",
    "PHYSICAL_KN",
    "USE_ACTIVATION",
    "ADD_BIAS",
]

_gemm_a16w16_basic_repr = make_kernel_repr(
    "_gemm_a16w16_gfx1250_basic_kernel", _GLUON_REPR_KEYS
)

_gemm_a16w16_lds_pipeline_repr = make_kernel_repr(
    "_gemm_a16w16_gfx1250_lds_pipeline_kernel", _GLUON_REPR_KEYS
)


def _get_config(M: int, N: int, K: int):
    config, is_tuned = get_gemm_config("GEMM-A16W16", M, N, K)
    return config, is_tuned


def create_shared_layouts(
    BLOCK_M: gl.constexpr,
    BLOCK_N: gl.constexpr,
    BLOCK_K: gl.constexpr,
    PHYSICAL_MK: gl.constexpr,
    PHYSICAL_KN: gl.constexpr,
):
    if PHYSICAL_MK:
        SHARED_LAYOUT_A: gl.constexpr = gl.PaddedSharedLayout.with_identity_for(
            [[BLOCK_K, 8]], [BLOCK_M, BLOCK_K], [1, 0]
        )
    else:
        SHARED_LAYOUT_A: gl.constexpr = gl.PaddedSharedLayout.with_identity_for(
            [[BLOCK_M, 8]], [BLOCK_K, BLOCK_M], [1, 0]
        )

    if PHYSICAL_KN:
        SHARED_LAYOUT_B: gl.constexpr = gl.PaddedSharedLayout.with_identity_for(
            [[BLOCK_N, 16]], [BLOCK_K, BLOCK_N], [1, 0]
        )
    else:
        SHARED_LAYOUT_B: gl.constexpr = gl.PaddedSharedLayout.with_identity_for(
            [[BLOCK_K, 8]], [BLOCK_N, BLOCK_K], [1, 0]
        )

    return (SHARED_LAYOUT_A, SHARED_LAYOUT_B)


@gluon.jit(repr=_gemm_a16w16_basic_repr)
def _gemm_a16w16_basic_kernel(
    a_ptr,
    b_ptr,
    c_ptr,
    bias_ptr,
    M,
    N,
    K,
    stride_am,
    stride_ak,
    stride_bk,
    stride_bn,
    stride_cm,
    stride_cn,
    BLOCK_M: gl.constexpr,
    BLOCK_N: gl.constexpr,
    BLOCK_K: gl.constexpr,
    NUM_BUFFERS: gl.constexpr,
    PHYSICAL_MK: gl.constexpr,
    PHYSICAL_KN: gl.constexpr,
    SHARED_LAYOUT_A: gl.constexpr,
    SHARED_LAYOUT_B: gl.constexpr,
    WMMA_LAYOUT: gl.constexpr,
    OPERAND_LAYOUT_A: gl.constexpr,
    OPERAND_LAYOUT_B: gl.constexpr,
    activation: gl.constexpr,
    USE_ACTIVATION: gl.constexpr,
    ADD_BIAS: gl.constexpr,
):
    pid = gl.program_id(axis=0)
    num_pid_m = gl.cdiv(M, BLOCK_M)
    pid_m = pid % num_pid_m
    pid_n = pid // num_pid_m

    # Descriptors start at this block's (M, N) offset by biasing the base
    # pointer — subsequent async_loads use [0, 0] and step only along K.
    a_base = a_ptr + pid_m * BLOCK_M * stride_am
    b_base = b_ptr + pid_n * BLOCK_N * stride_bn

    if PHYSICAL_MK:
        a_desc = gl.amd.gfx1250.tdm.make_tensor_descriptor(
            base=a_base,
            shape=(M - pid_m * BLOCK_M, K),
            strides=(stride_am, stride_ak),
            block_shape=(BLOCK_M, BLOCK_K),
            layout=SHARED_LAYOUT_A,
        )
    else:
        a_desc = gl.amd.gfx1250.tdm.make_tensor_descriptor(
            base=a_base,
            shape=(K, M - pid_m * BLOCK_M),
            strides=(stride_ak, stride_am),
            block_shape=(BLOCK_K, BLOCK_M),
            layout=SHARED_LAYOUT_A,
        )

    if PHYSICAL_KN:
        b_desc = gl.amd.gfx1250.tdm.make_tensor_descriptor(
            base=b_base,
            shape=(K, N - pid_n * BLOCK_N),
            strides=(stride_bk, stride_bn),
            block_shape=(BLOCK_K, BLOCK_N),
            layout=SHARED_LAYOUT_B,
        )
    else:
        b_desc = gl.amd.gfx1250.tdm.make_tensor_descriptor(
            base=b_base,
            shape=(N - pid_n * BLOCK_N, K),
            strides=(stride_bn, stride_bk),
            block_shape=(BLOCK_N, BLOCK_K),
            layout=SHARED_LAYOUT_B,
        )

    if PHYSICAL_MK:
        a_buffer = gl.allocate_shared_memory(
            a_ptr.type.element_ty,
            shape=[NUM_BUFFERS, BLOCK_M, BLOCK_K],
            layout=SHARED_LAYOUT_A,
        )
    else:
        a_buffer = gl.allocate_shared_memory(
            a_ptr.type.element_ty,
            shape=[NUM_BUFFERS, BLOCK_K, BLOCK_M],
            layout=SHARED_LAYOUT_A,
        )

    if PHYSICAL_KN:
        b_buffer = gl.allocate_shared_memory(
            b_ptr.type.element_ty,
            shape=[NUM_BUFFERS, BLOCK_K, BLOCK_N],
            layout=SHARED_LAYOUT_B,
        )
    else:
        b_buffer = gl.allocate_shared_memory(
            b_ptr.type.element_ty,
            shape=[NUM_BUFFERS, BLOCK_N, BLOCK_K],
            layout=SHARED_LAYOUT_B,
        )

    load_idx = 0
    compute_idx = 0

    accumulator = gl.zeros((BLOCK_M, BLOCK_N), dtype=gl.float32, layout=WMMA_LAYOUT)

    # Fill the pipeline
    for _ in gl.static_range(NUM_BUFFERS - 1):
        gl.amd.gfx1250.tdm.async_load(
            a_desc, [0, 0], a_buffer.index(load_idx % NUM_BUFFERS)
        )
        gl.amd.gfx1250.tdm.async_load(
            b_desc, [0, 0], b_buffer.index(load_idx % NUM_BUFFERS)
        )

        # Walk the descriptors forward one K tile.
        if PHYSICAL_MK:
            a_desc = gl.amd.gfx1250.tdm.update_tensor_descriptor(
                a_desc, add_offsets=[0, BLOCK_K]
            )
        else:
            a_desc = gl.amd.gfx1250.tdm.update_tensor_descriptor(
                a_desc, add_offsets=[BLOCK_K, 0]
            )

        if PHYSICAL_KN:
            b_desc = gl.amd.gfx1250.tdm.update_tensor_descriptor(
                b_desc, add_offsets=[BLOCK_K, 0]
            )
        else:
            b_desc = gl.amd.gfx1250.tdm.update_tensor_descriptor(
                b_desc, add_offsets=[0, BLOCK_K]
            )

        load_idx += 1

    # Main pipeline loop
    num_k_tiles = gl.cdiv(K, BLOCK_K)

    for _ in range(num_k_tiles - (NUM_BUFFERS - 1)):
        gl.amd.gfx1250.tdm.async_load(
            a_desc, [0, 0], a_buffer.index(load_idx % NUM_BUFFERS)
        )
        gl.amd.gfx1250.tdm.async_load(
            b_desc, [0, 0], b_buffer.index(load_idx % NUM_BUFFERS)
        )

        gl.amd.gfx1250.tdm.async_wait((NUM_BUFFERS - 1) * 2)

        # Walk the descriptors forward one K tile.
        if PHYSICAL_MK:
            a_desc = gl.amd.gfx1250.tdm.update_tensor_descriptor(
                a_desc, add_offsets=[0, BLOCK_K]
            )
        else:
            a_desc = gl.amd.gfx1250.tdm.update_tensor_descriptor(
                a_desc, add_offsets=[BLOCK_K, 0]
            )

        if PHYSICAL_KN:
            b_desc = gl.amd.gfx1250.tdm.update_tensor_descriptor(
                b_desc, add_offsets=[BLOCK_K, 0]
            )
        else:
            b_desc = gl.amd.gfx1250.tdm.update_tensor_descriptor(
                b_desc, add_offsets=[0, BLOCK_K]
            )

        load_idx += 1

        if PHYSICAL_MK:
            cur_a = gl.amd.cdna4.async_copy.load_shared_relaxed(
                a_buffer.index(compute_idx % NUM_BUFFERS), OPERAND_LAYOUT_A
            )
        else:
            cur_a = gl.amd.cdna4.async_copy.load_shared_relaxed(
                a_buffer.index(compute_idx % NUM_BUFFERS).permute([1, 0]),
                OPERAND_LAYOUT_A,
            )

        if PHYSICAL_KN:
            cur_b = gl.amd.cdna4.async_copy.load_shared_relaxed(
                b_buffer.index(compute_idx % NUM_BUFFERS), OPERAND_LAYOUT_B
            )
        else:
            cur_b = gl.amd.cdna4.async_copy.load_shared_relaxed(
                b_buffer.index(compute_idx % NUM_BUFFERS).permute([1, 0]),
                OPERAND_LAYOUT_B,
            )

        accumulator = gl.amd.gfx1250.wmma(cur_a, cur_b, accumulator)

        compute_idx += 1

    # Epilogue: no more loads
    for i in gl.static_range(NUM_BUFFERS - 1):
        gl.amd.gfx1250.tdm.async_wait((NUM_BUFFERS - 2 - i) * 2)

        if PHYSICAL_MK:
            cur_a = gl.amd.cdna4.async_copy.load_shared_relaxed(
                a_buffer.index(compute_idx % NUM_BUFFERS), OPERAND_LAYOUT_A
            )
        else:
            cur_a = gl.amd.cdna4.async_copy.load_shared_relaxed(
                a_buffer.index(compute_idx % NUM_BUFFERS).permute([1, 0]),
                OPERAND_LAYOUT_A,
            )

        if PHYSICAL_KN:
            cur_b = gl.amd.cdna4.async_copy.load_shared_relaxed(
                b_buffer.index(compute_idx % NUM_BUFFERS), OPERAND_LAYOUT_B
            )
        else:
            cur_b = gl.amd.cdna4.async_copy.load_shared_relaxed(
                b_buffer.index(compute_idx % NUM_BUFFERS).permute([1, 0]),
                OPERAND_LAYOUT_B,
            )

        accumulator = gl.amd.gfx1250.wmma(cur_a, cur_b, accumulator)
        compute_idx += 1

    # Bias
    if ADD_BIAS:
        offs_bias = pid_n * BLOCK_N + gl.arange(
            0, BLOCK_N, layout=gl.SliceLayout(0, WMMA_LAYOUT)
        )
        bias_vals = gl.load(bias_ptr + offs_bias, mask=offs_bias < N, other=0.0)
        accumulator = accumulator + bias_vals[None, :]

    # Activation
    if USE_ACTIVATION:
        accumulator = activation(accumulator)

    offs_cm = pid_m * BLOCK_M + gl.arange(
        0, BLOCK_M, layout=gl.SliceLayout(1, WMMA_LAYOUT)
    )
    offs_cn = pid_n * BLOCK_N + gl.arange(
        0, BLOCK_N, layout=gl.SliceLayout(0, WMMA_LAYOUT)
    )

    offs_c = stride_cm * offs_cm[:, None] + stride_cn * offs_cn[None, :]

    mask_c = (offs_cm[:, None] < M) & (offs_cn[None, :] < N)

    # Store
    gl.amd.gfx1250.buffer_store(
        accumulator.to(c_ptr.type.element_ty), c_ptr, offs_c, mask=mask_c
    )


@gluon.jit(repr=_gemm_a16w16_lds_pipeline_repr)
def _gemm_a16w16_lds_pipeline_kernel(
    a_ptr,
    b_ptr,
    c_ptr,
    bias_ptr,
    M,
    N,
    K,
    stride_am,
    stride_ak,
    stride_bk,
    stride_bn,
    stride_cm,
    stride_cn,
    BLOCK_M: gl.constexpr,
    BLOCK_N: gl.constexpr,
    BLOCK_K: gl.constexpr,
    NUM_BUFFERS: gl.constexpr,
    PHYSICAL_MK: gl.constexpr,
    PHYSICAL_KN: gl.constexpr,
    SHARED_LAYOUT_A: gl.constexpr,
    SHARED_LAYOUT_B: gl.constexpr,
    WMMA_LAYOUT: gl.constexpr,
    OPERAND_LAYOUT_A: gl.constexpr,
    OPERAND_LAYOUT_B: gl.constexpr,
    activation: gl.constexpr,
    USE_ACTIVATION: gl.constexpr,
    ADD_BIAS: gl.constexpr,
):
    """Local-load pipelining across K-tiles.

    Manually places load_shared_relaxed for tile i+1 *before* the wmma for
    tile i so the hardware LDS unit and matrix unit can run in parallel.
    LLVM fails to schedule this reordering on its own in the basic kernel.

    Requires NUM_BUFFERS >= 2.  With NUM_BUFFERS == 2 the TDM must complete
    fully before each ds_read batch (async_wait(0)), but the ds_read/wmma
    overlap is still preserved.  NUM_BUFFERS >= 3 is recommended.
    """
    gl.static_assert(NUM_BUFFERS >= 2, "lds_pipeline kernel requires NUM_BUFFERS >= 2")

    pid = gl.program_id(axis=0)
    num_pid_m = gl.cdiv(M, BLOCK_M)
    pid_m = pid % num_pid_m
    pid_n = pid // num_pid_m

    # Descriptors start at this block's (M, N) offset by biasing the base
    # pointer — subsequent async_loads use [0, 0] and step only along K.
    a_base = a_ptr + pid_m * BLOCK_M * stride_am
    b_base = b_ptr + pid_n * BLOCK_N * stride_bn

    if PHYSICAL_MK:
        a_desc = gl.amd.gfx1250.tdm.make_tensor_descriptor(
            base=a_base,
            shape=(M - pid_m * BLOCK_M, K),
            strides=(stride_am, stride_ak),
            block_shape=(BLOCK_M, BLOCK_K),
            layout=SHARED_LAYOUT_A,
        )
    else:
        a_desc = gl.amd.gfx1250.tdm.make_tensor_descriptor(
            base=a_base,
            shape=(K, M - pid_m * BLOCK_M),
            strides=(stride_ak, stride_am),
            block_shape=(BLOCK_K, BLOCK_M),
            layout=SHARED_LAYOUT_A,
        )

    if PHYSICAL_KN:
        b_desc = gl.amd.gfx1250.tdm.make_tensor_descriptor(
            base=b_base,
            shape=(K, N - pid_n * BLOCK_N),
            strides=(stride_bk, stride_bn),
            block_shape=(BLOCK_K, BLOCK_N),
            layout=SHARED_LAYOUT_B,
        )
    else:
        b_desc = gl.amd.gfx1250.tdm.make_tensor_descriptor(
            base=b_base,
            shape=(N - pid_n * BLOCK_N, K),
            strides=(stride_bn, stride_bk),
            block_shape=(BLOCK_N, BLOCK_K),
            layout=SHARED_LAYOUT_B,
        )

    if PHYSICAL_MK:
        a_buffer = gl.allocate_shared_memory(
            a_ptr.type.element_ty,
            shape=[NUM_BUFFERS, BLOCK_M, BLOCK_K],
            layout=SHARED_LAYOUT_A,
        )
    else:
        a_buffer = gl.allocate_shared_memory(
            a_ptr.type.element_ty,
            shape=[NUM_BUFFERS, BLOCK_K, BLOCK_M],
            layout=SHARED_LAYOUT_A,
        )

    if PHYSICAL_KN:
        b_buffer = gl.allocate_shared_memory(
            b_ptr.type.element_ty,
            shape=[NUM_BUFFERS, BLOCK_K, BLOCK_N],
            layout=SHARED_LAYOUT_B,
        )
    else:
        b_buffer = gl.allocate_shared_memory(
            b_ptr.type.element_ty,
            shape=[NUM_BUFFERS, BLOCK_N, BLOCK_K],
            layout=SHARED_LAYOUT_B,
        )

    load_idx = 0
    compute_idx = 0

    accumulator = gl.zeros((BLOCK_M, BLOCK_N), dtype=gl.float32, layout=WMMA_LAYOUT)

    # TDM prologue: fill the pipeline with NUM_BUFFERS-1 tiles
    for _ in gl.static_range(NUM_BUFFERS):
        gl.amd.gfx1250.tdm.async_load(
            a_desc, [0, 0], a_buffer.index(load_idx % NUM_BUFFERS)
        )
        gl.amd.gfx1250.tdm.async_load(
            b_desc, [0, 0], b_buffer.index(load_idx % NUM_BUFFERS)
        )

        # Walk the descriptors forward one K tile.
        if PHYSICAL_MK:
            a_desc = gl.amd.gfx1250.tdm.update_tensor_descriptor(
                a_desc, add_offsets=[0, BLOCK_K]
            )
        else:
            a_desc = gl.amd.gfx1250.tdm.update_tensor_descriptor(
                a_desc, add_offsets=[BLOCK_K, 0]
            )

        if PHYSICAL_KN:
            b_desc = gl.amd.gfx1250.tdm.update_tensor_descriptor(
                b_desc, add_offsets=[BLOCK_K, 0]
            )
        else:
            b_desc = gl.amd.gfx1250.tdm.update_tensor_descriptor(
                b_desc, add_offsets=[0, BLOCK_K]
            )

        load_idx += 1

    num_k_tiles = gl.cdiv(K, BLOCK_K)

    # Register pre-load prologue: wait for tile 0 then read it into cur_a/cur_b.
    # After TDM prologue there are (NUM_BUFFERS-1)*2 ops in-flight; waiting for
    # (NUM_BUFFERS-2)*2 lets exactly one tile (tile 0) complete.
    gl.amd.gfx1250.tdm.async_wait((NUM_BUFFERS - 1) * 2)

    if PHYSICAL_MK:
        cur_a = gl.amd.cdna4.async_copy.load_shared_relaxed(
            a_buffer.index(compute_idx % NUM_BUFFERS), OPERAND_LAYOUT_A
        )
    else:
        cur_a = gl.amd.cdna4.async_copy.load_shared_relaxed(
            a_buffer.index(compute_idx % NUM_BUFFERS).permute([1, 0]),
            OPERAND_LAYOUT_A,
        )

    if PHYSICAL_KN:
        cur_b = gl.amd.cdna4.async_copy.load_shared_relaxed(
            b_buffer.index(compute_idx % NUM_BUFFERS), OPERAND_LAYOUT_B
        )
    else:
        cur_b = gl.amd.cdna4.async_copy.load_shared_relaxed(
            b_buffer.index(compute_idx % NUM_BUFFERS).permute([1, 0]),
            OPERAND_LAYOUT_B,
        )

    # Main pipeline loop — first iteration peeled out below, then loop runs
    # for (num_k_tiles - (NUM_BUFFERS - 1) - 1) remaining iterations.

    # ---- Peeled first iteration ----
    # WMMA for the current tile — uses operands pre-loaded in the
    # *previous* iteration so no ds_read stall before the matrix op.
    accumulator = gl.amd.gfx1250.wmma(cur_a, cur_b, accumulator)

    # Issue TDM for the tile that is (NUM_BUFFERS-1) steps ahead
    gl.amd.gfx1250.tdm.async_load(
        a_desc, [0, 0], a_buffer.index(load_idx % NUM_BUFFERS)
    )
    gl.amd.gfx1250.tdm.async_load(
        b_desc, [0, 0], b_buffer.index(load_idx % NUM_BUFFERS)
    )

    # Walk the descriptors forward one K tile.
    if PHYSICAL_MK:
        a_desc = gl.amd.gfx1250.tdm.update_tensor_descriptor(
            a_desc, add_offsets=[0, BLOCK_K]
        )
    else:
        a_desc = gl.amd.gfx1250.tdm.update_tensor_descriptor(
            a_desc, add_offsets=[BLOCK_K, 0]
        )

    if PHYSICAL_KN:
        b_desc = gl.amd.gfx1250.tdm.update_tensor_descriptor(
            b_desc, add_offsets=[BLOCK_K, 0]
        )
    else:
        b_desc = gl.amd.gfx1250.tdm.update_tensor_descriptor(
            b_desc, add_offsets=[0, BLOCK_K]
        )

    # Tighter wait: after issuing the new TDM there are (NUM_BUFFERS-1)*2
    # ops in-flight.  Waiting for (NUM_BUFFERS-2)*2 guarantees that tile
    # compute_idx+1 has landed in LDS.
    gl.amd.gfx1250.tdm.async_wait((NUM_BUFFERS - 1) * 2)

    load_idx += 1

    # Pre-load the NEXT tile's operands into registers *before* the WMMA
    # below.  The hardware can run LDS reads and the matrix unit in
    # parallel, hiding the ds_read latency inside the WMMA execution.
    if PHYSICAL_MK:
        next_a = gl.amd.cdna4.async_copy.load_shared_relaxed(
            a_buffer.index((compute_idx + 1) % NUM_BUFFERS), OPERAND_LAYOUT_A
        )
    else:
        next_a = gl.amd.cdna4.async_copy.load_shared_relaxed(
            a_buffer.index((compute_idx + 1) % NUM_BUFFERS).permute([1, 0]),
            OPERAND_LAYOUT_A,
        )

    if PHYSICAL_KN:
        next_b = gl.amd.cdna4.async_copy.load_shared_relaxed(
            b_buffer.index((compute_idx + 1) % NUM_BUFFERS), OPERAND_LAYOUT_B
        )
    else:
        next_b = gl.amd.cdna4.async_copy.load_shared_relaxed(
            b_buffer.index((compute_idx + 1) % NUM_BUFFERS).permute([1, 0]),
            OPERAND_LAYOUT_B,
        )

    cur_a = next_a
    cur_b = next_b
    compute_idx += 1

    # ---- Remaining main-loop iterations ----
    for _ in range(num_k_tiles - NUM_BUFFERS - 1):

        # WMMA for the current tile — uses operands pre-loaded in the
        # *previous* iteration so no ds_read stall before the matrix op.
        accumulator = gl.amd.gfx1250.wmma(cur_a, cur_b, accumulator)


        # Issue TDM for the tile that is (NUM_BUFFERS-1) steps ahead
        gl.amd.gfx1250.tdm.async_load(
            a_desc, [0, 0], a_buffer.index(load_idx % NUM_BUFFERS)
        )
        gl.amd.gfx1250.tdm.async_load(
            b_desc, [0, 0], b_buffer.index(load_idx % NUM_BUFFERS)
        )

        # Walk the descriptors forward one K tile.
        if PHYSICAL_MK:
            a_desc = gl.amd.gfx1250.tdm.update_tensor_descriptor(
                a_desc, add_offsets=[0, BLOCK_K]
            )
        else:
            a_desc = gl.amd.gfx1250.tdm.update_tensor_descriptor(
                a_desc, add_offsets=[BLOCK_K, 0]
            )

        if PHYSICAL_KN:
            b_desc = gl.amd.gfx1250.tdm.update_tensor_descriptor(
                b_desc, add_offsets=[BLOCK_K, 0]
            )
        else:
            b_desc = gl.amd.gfx1250.tdm.update_tensor_descriptor(
                b_desc, add_offsets=[0, BLOCK_K]
            )

        # Tighter wait: after issuing the new TDM there are (NUM_BUFFERS-1)*2
        # ops in-flight.  Waiting for (NUM_BUFFERS-2)*2 guarantees that tile
        # compute_idx+1 has landed in LDS.
        gl.amd.gfx1250.tdm.async_wait((NUM_BUFFERS - 1) * 2)

        load_idx += 1

        # Pre-load the NEXT tile's operands into registers *before* the WMMA
        # below.  The hardware can run LDS reads and the matrix unit in
        # parallel, hiding the ds_read latency inside the WMMA execution.
        if PHYSICAL_MK:
            next_a = gl.amd.cdna4.async_copy.load_shared_relaxed(
                a_buffer.index((compute_idx + 1) % NUM_BUFFERS), OPERAND_LAYOUT_A
            )
        else:
            next_a = gl.amd.cdna4.async_copy.load_shared_relaxed(
                a_buffer.index((compute_idx + 1) % NUM_BUFFERS).permute([1, 0]),
                OPERAND_LAYOUT_A,
            )

        if PHYSICAL_KN:
            next_b = gl.amd.cdna4.async_copy.load_shared_relaxed(
                b_buffer.index((compute_idx + 1) % NUM_BUFFERS), OPERAND_LAYOUT_B
            )
        else:
            next_b = gl.amd.cdna4.async_copy.load_shared_relaxed(
                b_buffer.index((compute_idx + 1) % NUM_BUFFERS).permute([1, 0]),
                OPERAND_LAYOUT_B,
            )

        cur_a = next_a
        cur_b = next_b
        compute_idx += 1

    # Epilogue: no more TDM loads; drain the remaining NUM_BUFFERS-1 tiles.
    # The first NUM_BUFFERS-2 iterations still use the pre-load / WMMA pattern.
    for i in gl.static_range(NUM_BUFFERS - 1):
        gl.amd.gfx1250.tdm.async_wait((NUM_BUFFERS - 2 - i) * 2)

        if PHYSICAL_MK:
            next_a = gl.amd.cdna4.async_copy.load_shared_relaxed(
                a_buffer.index((compute_idx + 1) % NUM_BUFFERS), OPERAND_LAYOUT_A
            )
        else:
            next_a = gl.amd.cdna4.async_copy.load_shared_relaxed(
                a_buffer.index((compute_idx + 1) % NUM_BUFFERS).permute([1, 0]),
                OPERAND_LAYOUT_A,
            )

        if PHYSICAL_KN:
            next_b = gl.amd.cdna4.async_copy.load_shared_relaxed(
                b_buffer.index((compute_idx + 1) % NUM_BUFFERS), OPERAND_LAYOUT_B
            )
        else:
            next_b = gl.amd.cdna4.async_copy.load_shared_relaxed(
                b_buffer.index((compute_idx + 1) % NUM_BUFFERS).permute([1, 0]),
                OPERAND_LAYOUT_B,
            )
        accumulator = gl.amd.gfx1250.wmma(cur_a, cur_b, accumulator)

        cur_a = next_a
        cur_b = next_b
        compute_idx += 1

    # Final WMMA for the last pre-loaded tile
    accumulator = gl.amd.gfx1250.wmma(cur_a, cur_b, accumulator)

    # if NUM_BUFFERS > 2:
    #     gl.amd.sched_barrier(0)

    # Bias
    if ADD_BIAS:
        offs_bias = pid_n * BLOCK_N + gl.arange(
            0, BLOCK_N, layout=gl.SliceLayout(0, WMMA_LAYOUT)
        )
        bias_vals = gl.load(bias_ptr + offs_bias, mask=offs_bias < N, other=0.0)
        accumulator = accumulator + bias_vals[None, :]

    # Activation
    if USE_ACTIVATION:
        accumulator = activation(accumulator)

    # TDM Store: accumulator → shared memory → global memory
    SHARED_LAYOUT_C: gl.constexpr = gl.PaddedSharedLayout.with_identity_for(
        [[BLOCK_N, 8]], [BLOCK_M, BLOCK_N], [1, 0]
    )
    c_buffer = gl.allocate_shared_memory(
        c_ptr.type.element_ty,
        shape=[BLOCK_M, BLOCK_N],
        layout=SHARED_LAYOUT_C,
    )
    c_buffer.store(accumulator.to(c_ptr.type.element_ty))

    # Ensure all wavefronts have finished writing to LDS before TDM reads it.
    gl.barrier()

    c_desc = gl.amd.gfx1250.tdm.make_tensor_descriptor(
        base=c_ptr,
        shape=(M, N),
        strides=(stride_cm, stride_cn),
        block_shape=(BLOCK_M, BLOCK_N),
        layout=SHARED_LAYOUT_C,
    )
    gl.amd.gfx1250.tdm.async_store(
        c_desc, [pid_m * BLOCK_M, pid_n * BLOCK_N], c_buffer
    )
    gl.amd.gfx1250.tdm.async_wait(0)


_KERNEL_MAP = {
    "basic": _gemm_a16w16_basic_kernel,
    "lds_pipeline": _gemm_a16w16_lds_pipeline_kernel,
}


def gemm_a16w16_gfx1250(
    x: torch.Tensor,
    w: torch.Tensor,
    bias: Optional[torch.Tensor] = None,
    dtype: torch.dtype = torch.bfloat16,
    y: Optional[torch.Tensor] = None,
    config: Optional[Dict] = None,
    activation: Optional[str] = None,
    kernel_type: str = "basic",
):
    """
    Compute 16 bit gemm y = x @ w^T + bias using gluon (gfx1250).

    Args:
        x: Input tensor of shape (M, K)
        w: Weight tensor of shape (N, K), internally transposed
        bias: Optional bias tensor of shape (N,)
        dtype: Output data type
        y: Optional pre-allocated output tensor
        config: Kernel tuning parameters:
            - BLOCK_M: Tile size in M dimension (default: 128)
            - BLOCK_N: Tile size in N dimension (default: 128)
            - BLOCK_K: Tile size in K dimension (default: 32)
            - NUM_BUFFERS: Pipeline stages (default: 2)
            - num_warps: Warps per block (default: 8)
        activation: Activation function ("gelu", "gelu_tanh", "silu", "silu_exp2", "relu")
        kernel_type: Kernel variant to use:
            - "basic": Simple pipelining with async TDM loads (default)
            - "lds_pipeline": Manually pipelines LDS loads across K-tiles; places
              load_shared_relaxed for tile i+1 before wmma for tile i so the
              hardware LDS unit and matrix unit run in parallel (requires NUM_BUFFERS >= 2,
              NUM_BUFFERS >= 3 recommended)

    Returns:
        Output tensor of shape (M, N)
    """

    assert (
        kernel_type in _KERNEL_MAP
    ), f"Unknown kernel_type '{kernel_type}', must be one of {list(_KERNEL_MAP.keys())}"

    _LOGGER.info(
        f"GEMM_A16W16 [gluon/gfx1250]: x={tuple(x.shape)} w={tuple(w.shape)} kernel={kernel_type}"
    )

    assert x.dtype in (
        torch.float16,
        torch.bfloat16,
    ), f"Activations (x) must be fp16 or bf16, got {x.dtype}"
    assert w.dtype in (
        torch.float16,
        torch.bfloat16,
    ), f"Weights (w) must be fp16 or bf16, got {w.dtype}"
    assert x.shape[1] == w.shape[1], "Incompatible matrix shapes."

    M, K = x.shape
    N, _ = w.shape

    if config is None:
        config, _ = _get_config(M, N, K)

    BLOCK_M = config["BLOCK_M"]
    BLOCK_N = config["BLOCK_N"]
    BLOCK_K = config["BLOCK_K"]
    NUM_BUFFERS = config.get("NUM_BUFFERS", 2)
    num_warps = config["num_warps"]

    # Pad K to be divisible by block k so tdm loads never read out of bounds
    K_padded = triton.cdiv(K, BLOCK_K) * BLOCK_K
    if K_padded != K:
        pad_size = K_padded - K
        x = torch.nn.functional.pad(x, (0, pad_size))
        w = torch.nn.functional.pad(w, (0, pad_size))
        K = K_padded

    # Clamp the software-pipeline depth to the number of K-tiles.
    #
    # The prologue/epilogue walk a fixed number of K-tiles determined by
    # NUM_BUFFERS, independent of how many real tiles exist. If NUM_BUFFERS
    # exceeds that count the descriptor base advances past the end of K while
    # its bound stays stale (add_offsets never shrinks it), so TDM OOB
    # zero-fill cannot fire and the WMMA consumes garbage. Cap the depth at the
    # real tile count. Variants differ in reach and in the minimum depth they
    # require:
    #   basic : reaches num_k_tiles -> cap = num_k_tiles
    #   lds_pipeline : preloads one tile ahead (needs num_k_tiles >= NB + 1)
    #                  -> cap = num_k_tiles - 1
    num_k_tiles = triton.cdiv(K, BLOCK_K)
    _MIN_BUFFERS = {"basic": 1, "lds_pipeline": 2}
    _DEPTH_SLACK = {"lds_pipeline": 1}

    # Fall back to the basic kernel when the requested variant cannot satisfy
    # its minimum pipeline depth for this K. The deeper variants reach more
    # K-tiles (lds_pipeline preloads one tile ahead) and assert a minimum
    # NUM_BUFFERS, so for few K-tiles they cannot run correctly. The basic
    # kernel has no such floor (min depth 1) and is valid for every K, so we
    # downgrade rather than error -- callers require a functional result for
    # any shape, and a slower-but-correct kernel is acceptable.
    depth_cap = num_k_tiles - _DEPTH_SLACK.get(kernel_type, 0)
    if depth_cap < _MIN_BUFFERS[kernel_type]:
        needed = _MIN_BUFFERS[kernel_type] + _DEPTH_SLACK.get(kernel_type, 0)
        _LOGGER.info(
            f"GEMM_A16W16 [gluon/gfx1250]: kernel_type='{kernel_type}' needs "
            f"num_k_tiles>={needed} but num_k_tiles={num_k_tiles} "
            f"(K={K}, BLOCK_K={BLOCK_K}); falling back to kernel_type='basic'."
        )
        kernel_type = "basic"
        depth_cap = num_k_tiles  # basic: depth slack 0, min depth 1

    NUM_BUFFERS = min(NUM_BUFFERS, depth_cap)

    w = w.T

    if x.stride(1) == 1:
        physical_mk = True
    elif x.stride(0) == 1:
        physical_mk = False
    else:
        raise ValueError(
            f"x must be contiguous in at least one dimension, got strides {x.stride()}"
        )

    if w.stride(1) == 1:
        physical_kn = True
    elif w.stride(0) == 1:
        physical_kn = False
    else:
        raise ValueError(
            f"w must be contiguous in at least one dimension, got strides {w.stride()}"
        )

    if y is None:
        y = torch.empty((M, N), dtype=dtype, device=x.device)

    warp_bases = [(0, 1)]
    for i in range(int(math.log2(num_warps // 2))):
        warp_bases.append((1 << i, 0))
    warp_bases = tuple(warp_bases)

    wmma_layout = gl.amd.AMDWMMALayout(
        version=3, transposed=True, warp_bases=warp_bases, instr_shape=[16, 16, 32]
    )

    operand_a = gl.DotOperandLayout(operand_index=0, parent=wmma_layout, k_width=8)
    operand_b = gl.DotOperandLayout(operand_index=1, parent=wmma_layout, k_width=8)

    shared_layouts = create_shared_layouts(
        BLOCK_M, BLOCK_N, BLOCK_K, physical_mk, physical_kn
    )
    shared_a, shared_b = shared_layouts[0], shared_layouts[1]

    num_tiles_m = triton.cdiv(M, BLOCK_M)
    num_tiles_n = triton.cdiv(N, BLOCK_N)
    grid = (num_tiles_m * num_tiles_n, 1)

    kernel_fn = _KERNEL_MAP[kernel_type]

    kernel_fn[grid](
        x,
        w,
        y,
        bias,
        M,
        N,
        K,
        x.stride(0),
        x.stride(1),
        w.stride(0),
        w.stride(1),
        y.stride(0),
        y.stride(1),
        BLOCK_M=BLOCK_M,
        BLOCK_N=BLOCK_N,
        BLOCK_K=BLOCK_K,
        NUM_BUFFERS=NUM_BUFFERS,
        PHYSICAL_MK=physical_mk,
        PHYSICAL_KN=physical_kn,
        SHARED_LAYOUT_A=shared_a,
        SHARED_LAYOUT_B=shared_b,
        WMMA_LAYOUT=wmma_layout,
        OPERAND_LAYOUT_A=operand_a,
        OPERAND_LAYOUT_B=operand_b,
        activation=_get_activation_from_str(activation) if activation else None,
        USE_ACTIVATION=activation is not None,
        ADD_BIAS=(bias is not None),
        num_warps=num_warps,
    )

    return y
