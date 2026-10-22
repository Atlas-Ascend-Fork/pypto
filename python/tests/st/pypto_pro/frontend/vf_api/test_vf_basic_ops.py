#!/usr/bin/env python3
# coding: utf-8
# Copyright (c) 2026 Huawei Technologies Co., Ltd.
# This program is free software, you can redistribute it and/or modify it under the terms and conditions of
# CANN Open Software License Agreement Version 2.0 (the "License").
# Please refer to the License for details. You may not use this file except in compliance with the License.
# THIS SOFTWARE IS PROVIDED ON AN "AS IS" BASIS, WITHOUT WARRANTIES OF ANY KIND, EITHER EXPRESS OR IMPLIED,
# INCLUDING BUT NOT LIMITED TO NON-INFRINGEMENT, MERCHANTABILITY, OR FITNESS FOR A PARTICULAR PURPOSE.
# See LICENSE in the root of the software repository for the full text of the License.
# -----------------------------------------------------------------------------------------------------------

import logging
import os

import pypto_pro.language as pl
from pypto_pro.language import Vf as vf  # noqa: N813
import pytest
import torch

import pypto

ST_DEVICE_ID = int(os.environ.get("TILE_FWK_DEVICE_ID", 0))
ST_DEVICE = f"npu:{ST_DEVICE_ID}"

M = 64
N = 1
TILE_SIZE = N * M * 4  # 256 bytes, 32-byte aligned

VA_IN_A = 0
VA_IN_B = VA_IN_A + TILE_SIZE
VA_F0 = VA_IN_B + TILE_SIZE
VA_F1 = VA_F0 + TILE_SIZE
VA_U0 = VA_F1 + TILE_SIZE
VA_U1 = VA_U0 + TILE_SIZE
VA_U2 = VA_U1 + TILE_SIZE


@pl.vector_function
def _vf_kernel_0_min_exp_0(in_a, in_b, t_f0, t_f1):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load_align(in_a, 0)
    reg_b = vf.load_align(in_b, 0)
    reg_dst = vf.min(reg_a, reg_b, preg)
    vf.store_align(t_f0, reg_dst, preg)
    reg_dst = vf.exp(reg_a, preg)
    vf.store_align(t_f1, reg_dst, preg)


@pl.jit()
def kernel_0_min_exp(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_0_min_exp_0(in_a, in_b, t_f0, t_f1)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_1_abs_sqrt_0(in_a, t_f0, t_f1):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load_align(in_a, 0)
    reg_dst = vf.abs(reg_a, preg)
    vf.store_align(t_f0, reg_dst, preg)
    reg_tmp = vf.abs(reg_a, preg)
    reg_dst = vf.sqrt(reg_tmp, preg)
    vf.store_align(t_f1, reg_dst, preg)


@pl.jit()
def kernel_1_abs_sqrt(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_1_abs_sqrt_0(in_a, t_f0, t_f1)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_2_bitwise_0(in_a, in_b, t_u0, t_u1, t_u2):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_UINT32)
    reg_a = vf.load_align(in_a, 0, dtype=pl.DT_UINT32)
    reg_b = vf.load_align(in_b, 0, dtype=pl.DT_UINT32)
    reg_dst = vf.or_(reg_a, reg_b, preg)
    vf.store_align(t_u0, reg_dst, preg)
    reg_dst = vf.not_(reg_a, preg)
    vf.store_align(t_u1, reg_dst, preg)
    reg_dst = vf.shift_left(reg_a, 2, preg)
    vf.store_align(t_u2, reg_dst, preg)


@pl.jit()
def kernel_2_bitwise(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_2_bitwise_0(in_a, in_b, t_u0, t_u1, t_u2)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_3_reduce_sum_max_0(in_a, t_f0, t_f1):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load_align(in_a, 0)
    reg_r = vf.reduce_sum(reg_a, preg)
    vf.store_align(t_f0, reg_r, preg)
    reg_r = vf.reduce_max(reg_a, preg)
    vf.store_align(t_f1, reg_r, preg)


@pl.jit()
def kernel_3_reduce_sum_max(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_3_reduce_sum_max_0(in_a, t_f0, t_f1)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_4_reduce_min_relu_0(in_a, t_f0, t_f1):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load_align(in_a, 0)
    reg_r = vf.reduce_min(reg_a, preg)
    vf.store_align(t_f0, reg_r, preg)
    reg_dst = vf.relu(reg_a, preg)
    vf.store_align(t_f1, reg_dst, preg)


@pl.jit()
def kernel_4_reduce_min_relu(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_4_reduce_min_relu_0(in_a, t_f0, t_f1)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_5_neg_adds_0(in_a, t_f0, t_f1):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load_align(in_a, 0)
    reg_dst = vf.neg(reg_a, preg)
    vf.store_align(t_f0, reg_dst, preg)
    reg_dst = vf.adds(reg_a, 3.14, preg)
    vf.store_align(t_f1, reg_dst, preg)


@pl.jit()
def kernel_5_neg_adds(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_5_neg_adds_0(in_a, t_f0, t_f1)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_6_mins_0(in_a, t_f0):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load_align(in_a, 0)
    reg_dst = vf.mins(reg_a, 0.5, preg)
    vf.store_align(t_f0, reg_dst, preg)


@pl.jit()
def kernel_6_mins(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_6_mins_0(in_a, t_f0)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_7_maxs_lrelu_0(in_a, t_f0, t_f1):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load_align(in_a, 0)
    reg_dst = vf.maxs(reg_a, -0.5, preg)
    vf.store_align(t_f0, reg_dst, preg)
    reg_dst = vf.leaky_relu(reg_a, 0.1, preg)
    vf.store_align(t_f1, reg_dst, preg)


@pl.jit()
def kernel_7_maxs_lrelu(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_7_maxs_lrelu_0(in_a, t_f0, t_f1)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_8_reduce_db_sum_max_0(in_a, t_f0, t_f1):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load_align(in_a, 0)
    reg_r = vf.reduce_sum(reg_a, preg, datablock=True)
    vf.store_align(t_f0, reg_r, preg)
    reg_r = vf.reduce_max(reg_a, preg, datablock=True)
    vf.store_align(t_f1, reg_r, preg)


@pl.jit()
def kernel_8_reduce_db_sum_max(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_8_reduce_db_sum_max_0(in_a, t_f0, t_f1)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_9_reduce_db_min_pair_0(in_a, t_f0, t_f1):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load_align(in_a, 0)
    reg_r = vf.reduce_min(reg_a, preg, datablock=True)
    vf.store_align(t_f0, reg_r, preg)
    reg_r = vf.pair_reduce_sum(reg_a, preg)
    vf.store_align(t_f1, reg_r, preg)


@pl.jit()
def kernel_9_reduce_db_min_pair(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_9_reduce_db_min_pair_0(in_a, t_f0, t_f1)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_10_abssub_axpy_0(in_a, in_b, t_f0, t_f1):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load_align(in_a, 0)
    reg_b = vf.load_align(in_b, 0)
    reg_dst = vf.abs_sub(reg_a, reg_b, preg)
    vf.store_align(t_f0, reg_dst, preg)
    reg_dst = vf.load_align(in_b, 0)
    reg_dst = vf.axpy(reg_a, 2.0, preg)
    vf.store_align(t_f1, reg_dst, preg)


@pl.jit()
def kernel_10_abssub_axpy(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_10_abssub_axpy_0(in_a, in_b, t_f0, t_f1)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_11_copy_madd_0(in_a, in_b, t_f0, t_f1):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load_align(in_a, 0)
    reg_b = vf.load_align(in_b, 0)
    reg_dst = vf.move(reg_a, preg)
    vf.store_align(t_f0, reg_dst, preg)
    reg_dst = vf.load_align(in_b, 0)
    reg_dst = vf.mul_dst_add(reg_a, reg_b, preg)
    vf.store_align(t_f1, reg_dst, preg)


@pl.jit()
def kernel_11_copy_madd(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_11_copy_madd_0(in_a, in_b, t_f0, t_f1)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_12_prelu_mul_0(in_a, in_b, t_f0, t_f1):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load_align(in_a, 0)
    reg_b = vf.load_align(in_b, 0)
    reg_dst = vf.prelu(reg_a, reg_b, preg)
    vf.store_align(t_f0, reg_dst, preg)
    reg_dst = vf.mul(reg_a, reg_b, preg)
    vf.store_align(t_f1, reg_dst, preg)


@pl.jit()
def kernel_12_prelu_mul(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_12_prelu_mul_0(in_a, in_b, t_f0, t_f1)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_13_shift_vec_0(in_a, in_b, t_u0, t_u1):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_INT32)
    reg_a = vf.load_align(in_a, 0, dtype=pl.DT_INT32)
    reg_b = vf.load_align(in_b, 0, dtype=pl.DT_INT32)
    reg_dst = vf.shift_left(reg_a, reg_b, preg)
    vf.store_align(t_u0, reg_dst, preg)
    reg_dst = vf.shift_right(reg_a, reg_b, preg)
    vf.store_align(t_u1, reg_dst, preg)


@pl.jit()
def kernel_13_shift_vec(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_13_shift_vec_0(in_a, in_b, t_u0, t_u1)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_14_mull_0(in_a, in_b, t_u0, t_u1):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_UINT32)
    reg_a = vf.load_align(in_a, 0, dtype=pl.DT_UINT32)
    reg_b = vf.load_align(in_b, 0, dtype=pl.DT_UINT32)
    reg_lo, reg_hi = vf.mull(reg_a, reg_b, preg)
    vf.store_align(t_u0, reg_lo, preg)
    vf.store_align(t_u1, reg_hi, preg)


@pl.jit()
def kernel_14_mull(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_14_mull_0(in_a, in_b, t_u0, t_u1)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_16_load_unalign_0(in_a, t_f0):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    ureg_load = vf.load_unalign_init()
    vf.load_unalign_pre(ureg_load, in_a)
    reg_dst = vf.load_unalign(ureg_load, in_a)
    vf.store_align(t_f0, reg_dst, preg)


@pl.jit()
def kernel_16_load_unalign(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_16_load_unalign_0(in_a, t_f0)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_19_arange_brc_0(in_a, t_f0):
    preg_f32 = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_dst = vf.load_align(in_a, 0, dist=pl.LoadDist.BRC)
    vf.store_align(t_f0, reg_dst, preg_f32)


@pl.jit()
def kernel_19_arange_brc(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_19_arange_brc_0(in_a, t_f0)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_20_rint_loadsample_0(in_a, t_f1):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load_align(in_a, 0)  # noqa: F841
    reg_dst = vf.load_align(in_a, 0, dist=pl.LoadDist.UNPK)
    vf.store_align(t_f1, reg_dst, preg)


@pl.jit()
def kernel_20_rint_loadsample(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_20_rint_loadsample_0(in_a, t_f1)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_21_pack_squeeze_v2_0(in_a, t_f0, t_f1):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load_align(in_a, 0)
    reg_dst = vf.squeeze(reg_a, preg, gather_mode=pl.SqueezeMode.STORE_REG)
    vf.store_align(t_f0, reg_dst, preg)
    reg_dst = vf.load_align(in_a, 0, dist=pl.LoadDist.UNPK)
    vf.store_align(t_f1, reg_dst, preg)


@pl.jit()
def kernel_21_pack_squeeze_v2(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_21_pack_squeeze_v2_0(in_a, t_f0, t_f1)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_22_cast_f32_to_s32_0(in_a, t_f0):
    preg_f32 = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load_align(in_a, 0)
    # DT_FP32 → DT_INT32 (truncate) → DT_FP32 roundtrip
    reg_s32 = vf.astype(reg_a, preg_f32, round_mode=pl.VFRoundMode.CAST_TRUNC, dtype=pl.DT_INT32)
    reg_dst = vf.astype(reg_s32, preg_f32, round_mode=pl.VFRoundMode.CAST_ROUND, dtype=pl.DT_FP32)
    vf.store_align(t_f0, reg_dst, preg_f32)


@pl.jit()
def kernel_22_cast_f32_to_s32(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_22_cast_f32_to_s32_0(in_a, t_f0)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_23_cast_s32_to_f32_0(in_a, t_f0):
    preg_f32 = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load_align(in_a, 0)
    # DT_FP32 → DT_INT32 (floor) → DT_FP32 roundtrip
    reg_s32 = vf.astype(reg_a, preg_f32, round_mode=pl.VFRoundMode.CAST_FLOOR, dtype=pl.DT_INT32)
    reg_dst = vf.astype(reg_s32, preg_f32, round_mode=pl.VFRoundMode.CAST_ROUND, dtype=pl.DT_FP32)
    vf.store_align(t_f0, reg_dst, preg_f32)


@pl.jit()
def kernel_23_cast_s32_to_f32(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_23_cast_s32_to_f32_0(in_a, t_f0)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_24_cast_f32_to_f16_0(in_a, t_f0):
    preg_f32 = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load_align(in_a, 0)
    reg_h = vf.astype(reg_a, preg_f32, round_mode=pl.VFRoundMode.CAST_ROUND, dtype=pl.DT_FP16)
    reg_dst = vf.astype(reg_h, preg_f32, dtype=pl.DT_FP32)
    vf.store_align(t_f0, reg_dst, preg_f32)


@pl.jit()
def kernel_24_cast_f32_to_f16(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    th = pl.TileType(shape=[N, M], dtype=pl.DT_FP16, target_memory=pl.MemorySpace.Vec)  # noqa: F841
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_24_cast_f32_to_f16_0(in_a, t_f0)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_25_unpack_upper_lower_0(in_a, t_u0, t_u1):
    preg_u32 = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_UINT32)
    reg_src_u16 = vf.load_align(in_a, 0, dtype=pl.DT_UINT16)
    reg_dst_upper = vf.unpack(reg_src_u16, part=pl.PackPart.UPPER, dtype=pl.DT_UINT32)
    vf.store_align(t_u0, reg_dst_upper, preg_u32)
    reg_dst_lower = vf.unpack(reg_src_u16, part=pl.PackPart.LOWER, dtype=pl.DT_UINT32)
    vf.store_align(t_u1, reg_dst_lower, preg_u32)


@pl.jit()
def kernel_25_unpack_upper_lower(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_25_unpack_upper_lower_0(in_a, t_u0, t_u1)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_26_store_pack_intlv_0(in_a, t_f0, in_b, t_u0):
    preg_f32 = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    preg_u32 = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_UINT32)
    reg_a = vf.load_align(in_a, 0)
    vf.store_align(t_f0, reg_a, preg_f32, dist=pl.StoreDist.PACK)
    reg_a_u32 = vf.load_align(in_a, 0, dtype=pl.DT_UINT32)
    reg_b_u32 = vf.load_align(in_b, 0, dtype=pl.DT_UINT32)
    vf.store_align(t_u0, reg_a_u32, reg_b_u32, preg_u32, dist=pl.StoreDist.INTLV)


@pl.jit()
def kernel_26_store_pack_intlv(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_26_store_pack_intlv_0(in_a, t_f0, in_b, t_u0)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_27_duplicate_0(in_a, t_f0, t_f1):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load_align(in_a, 0)
    # Scalar broadcast: fill all lanes with 2.5
    reg_dst_scalar = vf.full(2.5, preg)
    vf.store_align(t_f0, reg_dst_scalar, preg)
    # Vector-source broadcast: broadcast lowest element of reg_a to all lanes
    reg_dst_vec = vf.full(reg_a, preg)
    vf.store_align(t_f1, reg_dst_vec, preg)


@pl.jit()
def kernel_27_duplicate(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_27_duplicate_0(in_a, t_f0, t_f1)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_28_get_mask_spr_0(in_a, t_f0):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load_align(in_a, 0)
    # Use get_mask_spr_b32 to retrieve mask from SPR after a compare
    cmp_mask = vf.ge(reg_a, 0.0, preg)  # noqa: F841
    spr_mask = vf.get_mask_spr(width=pl.MaskWidth.B32)
    # Use the spr_mask in a subsequent operation
    reg_dst = vf.abs(reg_a, spr_mask)
    vf.store_align(t_f0, reg_dst, preg)


@pl.jit()
def kernel_28_get_mask_spr(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_28_get_mask_spr_0(in_a, t_f0)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_29_store_pack_v2_0(in_a, t_f0):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load_align(in_a, 0)
    vf.store_align(t_f0, reg_a, preg, dist=pl.StoreDist.PACK4)


@pl.jit()
def kernel_29_store_pack_v2(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_29_store_pack_v2_0(in_a, t_f0)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_30_cast_f16_to_s32_0(in_a, t_f0):
    preg_f32 = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load_align(in_a, 0)
    # DT_FP32 → DT_FP16 (narrowing)
    reg_h = vf.astype(reg_a, preg_f32, round_mode=pl.VFRoundMode.CAST_ROUND, dtype=pl.DT_FP16)
    # DT_FP16 → DT_INT32 (widening float→int, uses ROUND + PART)
    reg_s32 = vf.astype(reg_h, preg_f32, round_mode=pl.VFRoundMode.CAST_TRUNC, dtype=pl.DT_INT32)
    # DT_INT32 → DT_FP32 (int→float)
    reg_dst = vf.astype(reg_s32, preg_f32, round_mode=pl.VFRoundMode.CAST_ROUND, dtype=pl.DT_FP32)
    vf.store_align(t_f0, reg_dst, preg_f32)


@pl.jit()
def kernel_30_cast_f16_to_s32(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    th = pl.TileType(shape=[N, M], dtype=pl.DT_FP16, target_memory=pl.MemorySpace.Vec)  # noqa: F841
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_30_cast_f16_to_s32_0(in_a, t_f0)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_31_load_brc_v2_0(in_a, t_f0):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    # BRC load via unified load_align
    reg_dst = vf.load_align(in_a, 0, dist=pl.LoadDist.BRC)
    reg_dst = vf.load_align(in_a, 0, dist=pl.LoadDist.BRC)
    vf.store_align(t_f0, reg_dst, preg)


@pl.jit()
def kernel_31_load_brc_v2(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_31_load_brc_v2_0(in_a, t_f0)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_32_postupdate_0(in_a, t_f0, t_f1):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    # load_align with BRC mode + POST_UPDATE in a loop
    reg_dst = vf.load_align(in_a, TILE_SIZE, dist=pl.LoadDist.BRC, post_update=True)
    reg_dst = vf.load_align(in_a, TILE_SIZE, dist=pl.LoadDist.BRC, post_update=True)
    vf.store_align(t_f0, reg_dst, preg)
    vf.store_align(t_f1, reg_dst, preg, dist=pl.StoreDist.PACK, post_update=True)
    vf.store_align(t_f1, reg_dst, preg, dist=pl.StoreDist.PACK, post_update=True)


@pl.jit()
def kernel_32_postupdate(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_32_postupdate_0(in_a, t_f0, t_f1)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_34_ln_0(in_a, t_f0):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load_align(in_a, 0)
    reg_dst = vf.ln(reg_a, preg)
    vf.store_align(t_f0, reg_dst, preg)


@pl.jit()
def kernel_34_ln(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_34_ln_0(in_a, t_f0)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_35_rsqrt_mov_0(in_a, t_f1):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load_align(in_a, 0)
    reg_mov = vf.move(reg_a, preg)
    vf.store_align(t_f1, reg_mov, preg)


@pl.jit()
def kernel_35_rsqrt_mov(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_35_rsqrt_mov_0(in_a, t_f1)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_36_mla_mov_0(in_a, in_b, t_f0, t_f1):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load_align(in_a, 0)
    reg_b = vf.load_align(in_b, 0)  # noqa: F841
    reg_dst = vf.load_align(in_b, 0)
    reg_dst = vf.mul_add_dst(reg_a, reg_a, preg)
    vf.store_align(t_f0, reg_dst, preg)
    # move: copy a to dst
    reg_dst = vf.move(reg_a, preg)
    vf.store_align(t_f1, reg_dst, preg)


@pl.jit()
def kernel_36_mla_mov(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_36_mla_mov_0(in_a, in_b, t_f0, t_f1)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_37_adif_0(in_a, in_b, t_f0, t_f1):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load_align(in_a, 0)
    reg_b = vf.load_align(in_b, 0)
    reg_dst = vf.full(0.0, preg)
    reg_dst = vf.abs_sub(reg_a, reg_b, preg)
    vf.store_align(t_f0, reg_dst, preg)
    # abs_sub again with different args for f1
    reg_dst = vf.full(0.0, preg)
    reg_dst = vf.abs_sub(reg_b, reg_a, preg)
    vf.store_align(t_f1, reg_dst, preg)


@pl.jit()
def kernel_37_adif(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_37_adif_0(in_a, in_b, t_f0, t_f1)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_38_avg_add3_0(in_a, in_b, t_f0, t_f1):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load_align(in_a, 0)
    reg_b = vf.load_align(in_b, 0)
    reg_dst = vf.add(reg_a, reg_b, preg)
    reg_dst = vf.muls(reg_dst, 0.5, preg)
    vf.store_align(t_f0, reg_dst, preg)
    reg_dst = vf.add(reg_a, reg_a, preg)
    reg_dst = vf.add(reg_dst, reg_b, preg)
    vf.store_align(t_f1, reg_dst, preg)


@pl.jit()
def kernel_38_avg_add3(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_38_avg_add3_0(in_a, in_b, t_f0, t_f1)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_39_selectr_max_0(in_a, in_b, t_f0, t_f1):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    preg_u32 = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_UINT32)
    reg_a = vf.load_align(in_a, 0)
    reg_b = vf.load_align(in_b, 0)
    # gather: broadcast element 0 from tile to all lanes (replaces select_r)
    reg_idx = vf.full(0, preg_u32, dtype=pl.DT_UINT32)
    reg_dst = vf.gather(in_a, reg_idx, preg_u32)
    # gather result is UINT32 reinterpret of FP32 data; move back as FP32
    reg_dst = vf.move(reg_dst, preg)
    vf.store_align(t_f0, reg_dst, preg)
    # max: element-wise max(a, b)
    reg_dst = vf.max(reg_a, reg_b, preg)
    vf.store_align(t_f1, reg_dst, preg)


@pl.jit()
def kernel_39_selectr_max(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_39_selectr_max_0(in_a, in_b, t_f0, t_f1)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_40_log2_log10_0(in_a, t_f0, t_f1):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load_align(in_a, 0)
    reg_dst = vf.log2(reg_a, preg)
    vf.store_align(t_f0, reg_dst, preg)
    reg_dst = vf.log10(reg_a, preg)
    vf.store_align(t_f1, reg_dst, preg)


@pl.jit()
def kernel_40_log2_log10(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_40_log2_log10_0(in_a, t_f0, t_f1)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_42_cast_fp162s4_roundtrip_0(in_a, t_f0):
    preg_f32 = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    preg_h = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP16)
    reg_a = vf.load_align(in_a, 0)
    reg_h = vf.astype(reg_a, preg_f32, round_mode=pl.VFRoundMode.CAST_ROUND, dtype=pl.DT_FP16)
    reg_dst = vf.astype(reg_h, preg_h, round_mode=pl.VFRoundMode.CAST_ROUND, dtype=pl.DT_INT4)
    reg_h = vf.astype(reg_dst, preg_h, dtype=pl.DT_FP16)
    reg_a = vf.astype(reg_h, preg_f32, dtype=pl.DT_FP32)
    vf.store_align(t_f0, reg_a, preg_f32)


@pl.jit()
def kernel_42_cast_fp162s4_roundtrip(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    th = pl.TileType(shape=[N, M], dtype=pl.DT_FP16, target_memory=pl.MemorySpace.Vec)  # noqa: F841
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_42_cast_fp162s4_roundtrip_0(in_a, t_f0)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_46_mask_logic_0(in_a, t_f0):
    preg0 = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    preg1 = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    preg_sel = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load_align(in_a, 0)
    preg_and = vf.and_(preg0, preg1, preg_sel)
    reg_dst = vf.abs(reg_a, preg_and)
    vf.store_align(t_f0, reg_dst, preg_and)


@pl.jit()
def kernel_46_mask_logic(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_46_mask_logic_0(in_a, t_f0)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_47_load_store_simple_0(in_a, t_f0):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load(in_a)
    reg_dst = vf.add(reg_a, reg_a, preg)
    vf.store(t_f0, reg_dst)


@pl.jit()
def kernel_47_load_store_simple(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_47_load_store_simple_0(in_a, t_f0)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_48_log_0(in_a, t_f0):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load_align(in_a, 0)
    reg_dst = vf.log(reg_a, preg)
    vf.store_align(t_f0, reg_dst, preg)


@pl.jit()
def kernel_48_log(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_48_log_0(in_a, t_f0)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_49_truncate_maskgen_0(in_a, in_b, t_f0, t_f1):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load_align(in_a, 0)
    reg_b = vf.load_align(in_b, 0)
    reg_dst = vf.truncate(reg_a, preg)
    vf.store_align(t_f0, reg_dst, preg)
    # Test mask_gen_with_reg_tensor: generate mask from DT_UINT32 reg bit 0
    # Load input b as uint32 (reinterpret), generate mask from bit 0, use with select
    reg_u32 = vf.load_align(in_b, 0)
    gen_mask = vf.mask_gen_with_reg_tensor(reg_u32, offset=0)
    reg_sel = vf.select(reg_a, reg_b, gen_mask)
    vf.store_align(t_f1, reg_sel, preg)


@pl.jit()
def kernel_49_truncate_maskgen(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_49_truncate_maskgen_0(in_a, in_b, t_f0, t_f1)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_50_sub_div_0(in_a, in_b, t_f0, t_f1):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load_align(in_a, 0)
    reg_b = vf.load_align(in_b, 0)
    reg_dst = vf.sub(reg_a, reg_b, preg)
    vf.store_align(t_f0, reg_dst, preg)
    reg_dst = vf.div(reg_a, reg_b, preg)
    vf.store_align(t_f1, reg_dst, preg)


@pl.jit()
def kernel_50_sub_div(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_50_sub_div_0(in_a, in_b, t_f0, t_f1)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_51_muls_and_xor_0(in_a, t_f0, in_b, t_u0, t_u1):
    preg_f32 = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    preg_u32 = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_UINT32)
    reg_a = vf.load_align(in_a, 0)
    reg_dst = vf.muls(reg_a, 2.5, preg_f32)
    vf.store_align(t_f0, reg_dst, preg_f32)
    reg_a_u32 = vf.load_align(in_a, 0)
    reg_b_u32 = vf.load_align(in_b, 0)
    reg_dst_u32 = vf.and_(reg_a_u32, reg_b_u32, preg_u32)
    vf.store_align(t_u0, reg_dst_u32, preg_u32)
    reg_dst_u32 = vf.xor(reg_a_u32, reg_b_u32, preg_u32)
    vf.store_align(t_u1, reg_dst_u32, preg_u32)


@pl.jit()
def kernel_51_muls_and_xor(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_51_muls_and_xor_0(in_a, t_f0, in_b, t_u0, t_u1)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_52_shift_rights_0(in_a, t_u0):
    preg_u32 = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_UINT32)
    reg_a_u32 = vf.load_align(in_a, 0, dtype=pl.DT_UINT32)
    reg_dst_u32 = vf.shift_right(reg_a_u32, 2, preg_u32)
    vf.store_align(t_u0, reg_dst_u32, preg_u32)


@pl.jit()
def kernel_52_shift_rights(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_52_shift_rights_0(in_a, t_u0)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_53_de_interleave_0(in_a, in_b, t_f0, t_f1):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load_align(in_a, 0)
    reg_b = vf.load_align(in_b, 0)
    reg_i0, reg_i1 = vf.interleave(reg_a, reg_b)
    reg_r0, reg_r1 = vf.de_interleave(reg_i0, reg_i1)
    vf.store_align(t_f0, reg_r0, preg)
    vf.store_align(t_f1, reg_r1, preg)


@pl.jit()
def kernel_53_de_interleave(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_53_de_interleave_0(in_a, in_b, t_f0, t_f1)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_54_pack_unpack_0(in_a, t_u0):
    preg_u32 = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_UINT32)
    reg_u32 = vf.load_align(in_a, 0, dtype=pl.DT_UINT32)
    reg_u16 = vf.pack(reg_u32, dtype=pl.DT_UINT16)
    reg_u32_out = vf.unpack(reg_u16, dtype=pl.DT_UINT32)
    vf.store_align(t_u0, reg_u32_out, preg_u32)


@pl.jit()
def kernel_54_pack_unpack(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_54_pack_unpack_0(in_a, t_u0)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_56_mul_add_dst_muls_cast_0(in_a, in_b, t_f0, t_f1):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load_align(in_a, 0)
    reg_b = vf.load_align(in_b, 0)
    reg_dst = vf.load_align(in_b, 0)
    reg_dst = vf.mul_add_dst(reg_a, reg_b, preg)
    vf.store_align(t_f0, reg_dst, preg)
    reg_a2 = vf.load_align(in_a, 0)
    reg_h = vf.muls_cast(reg_a2, 2.0, preg, dtype=pl.DT_FP16)
    reg_dst = vf.astype(reg_h, preg, dtype=pl.DT_FP32)
    vf.store_align(t_f1, reg_dst, preg)


@pl.jit()
def kernel_56_mul_add_dst_muls_cast(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_56_mul_add_dst_muls_cast_0(in_a, in_b, t_f0, t_f1)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_57_compare_0(in_a, in_b, t_f0):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load_align(in_a, 0)
    reg_b = vf.load_align(in_b, 0)
    cmp_mask = vf.gt(reg_a, reg_b, preg)
    reg_dst = vf.select(reg_a, reg_b, cmp_mask)
    vf.store_align(t_f0, reg_dst, preg)


@pl.jit()
def kernel_57_compare(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_57_compare_0(in_a, in_b, t_f0)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_58_cast_s42_bf16_int16_0(in_a, t_f0, t_f1):
    preg_f32 = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    preg_h = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP16)
    reg_a = vf.load_align(in_a, 0)
    reg_h = vf.astype(reg_a, preg_f32, round_mode=pl.VFRoundMode.CAST_ROUND, dtype=pl.DT_FP16)
    reg_s4 = vf.astype(reg_h, preg_h, round_mode=pl.VFRoundMode.CAST_ROUND, dtype=pl.DT_INT4)
    reg_bf16 = vf.astype(reg_s4, preg_h, dtype=pl.DT_BF16)
    reg_dst = vf.astype(reg_bf16, preg_f32, dtype=pl.DT_FP32)
    vf.store_align(t_f0, reg_dst, preg_f32)
    reg_s16 = vf.astype(reg_s4, preg_h, dtype=pl.DT_INT16)
    reg_dst = vf.astype(reg_s16, preg_f32, dtype=pl.DT_FP32)
    vf.store_align(t_f1, reg_dst, preg_f32)


@pl.jit()
def kernel_58_cast_s42_bf16_int16(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_58_cast_s42_bf16_int16_0(in_a, t_f0, t_f1)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_59_load_store_a_simple_0(in_a, t_f0):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load(in_a)
    reg_dst = vf.add(reg_a, reg_a, preg)
    vf.store(t_f0, reg_dst)


@pl.jit()
def kernel_59_load_store_a_simple(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_59_load_store_a_simple_0(in_a, t_f0)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_60_load_store_u_align_0(in_a, t_f0):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load(in_a)
    reg_dst = vf.add(reg_a, reg_a, preg)
    vf.store(t_f0, reg_dst)


@pl.jit()
def kernel_60_load_store_u_align(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_60_load_store_u_align_0(in_a, t_f0)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_61_load_unalign_post_update_0(in_a, t_f0):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    ureg_load = vf.load_unalign_init()
    vf.load_unalign_pre(ureg_load, in_a)
    reg_dst = vf.load_unalign(ureg_load, in_a, TILE_SIZE)
    vf.store_align(t_f0, reg_dst, preg)


@pl.jit()
def kernel_61_load_unalign_post_update(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_61_load_unalign_post_update_0(in_a, t_f0)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_62_scatter_0(in_a, in_idx, t_f0):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load_align(in_a, 0)
    reg_idx = vf.load_align(in_idx, 0, dtype=pl.DT_UINT32)
    vf.scatter(t_f0, reg_a, reg_idx, preg)


@pl.jit()
def kernel_62_scatter(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.load(t_u0, out_u0, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_62_scatter_0(in_a, t_u0, t_f0)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_65_update_mask_0(in_a, t_f0):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load_align(in_a, 0)
    preg_tail = vf.update_mask(8, dtype=pl.DT_FP32)
    reg_dst = vf.abs(reg_a, preg_tail)
    vf.store_align(t_f0, reg_dst, preg)


@pl.jit()
def kernel_65_update_mask(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_65_update_mask_0(in_a, t_f0)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_66_mask_or_xor_not_0(in_a, in_b, t_f0, t_f1):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load_align(in_a, 0)
    reg_b = vf.load_align(in_b, 0)
    mask_a = vf.ge(reg_a, 0.0, preg)
    mask_b = vf.ge(reg_b, 0.0, preg)
    preg_or = vf.or_(mask_a, mask_b, preg)
    reg_dst = vf.abs(reg_a, preg_or)
    vf.store_align(t_f0, reg_dst, preg_or)
    preg_xor = vf.xor(mask_a, mask_b, preg)
    reg_dst = vf.abs(reg_a, preg_xor)
    vf.store_align(t_f1, reg_dst, preg_xor)


@pl.jit()
def kernel_66_mask_or_xor_not(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_66_mask_or_xor_not_0(in_a, in_b, t_f0, t_f1)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_67_mask_mov_sel_0(in_a, t_f0, t_f1):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load_align(in_a, 0)
    mask_a = vf.ge(reg_a, 0.0, preg)
    preg_mov = vf.move(mask_a, preg)
    reg_dst = vf.abs(reg_a, preg_mov)
    vf.store_align(t_f0, reg_dst, preg_mov)
    mask_b = vf.lt(reg_a, 0.0, preg)
    preg_sel = vf.select(mask_a, mask_b, preg)
    reg_dst = vf.abs(reg_a, preg_sel)
    vf.store_align(t_f1, reg_dst, preg_sel)


@pl.jit()
def kernel_67_mask_mov_sel(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_67_mask_mov_sel_0(in_a, t_f0, t_f1)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_68_mask_load_store_0(in_a, t_u0, t_f0):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load_align(in_a, 0)
    mask_a = vf.ge(reg_a, 0.0, preg)
    vf.store_align(t_u0, mask_a, dist=pl.StoreDist.PACK)
    vf.mem_bar(mode=pl.MemBarMode.VST_VLD)
    preg_loaded = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    preg_loaded = vf.load_align(t_u0, dist=pl.LoadDist.US)
    reg_dst = vf.abs(reg_a, preg_loaded)
    vf.store_align(t_f0, reg_dst, preg)


@pl.jit()
def kernel_68_mask_load_store(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_68_mask_load_store_0(in_a, t_u0, t_f0)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_69_mask_pack_unpack_0(in_a, t_f0):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load_align(in_a, 0)
    mask_a = vf.ge(reg_a, 0.0, preg)
    preg_packed = vf.pack(mask_a, part=pl.PackPart.LOWER)
    preg_unpacked = vf.unpack(preg_packed, part=pl.PackPart.LOWER)
    reg_dst = vf.abs(reg_a, preg_unpacked)
    vf.store_align(t_f0, reg_dst, preg)


@pl.jit()
def kernel_69_mask_pack_unpack(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_69_mask_pack_unpack_0(in_a, t_f0)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_71_cast_cross_width_0(in_a, t_f0, t_f1):
    preg_f32 = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load_align(in_a, 0)
    # Test S32→FP32→FP16: cross-width via DT_FP32 intermediate (S32→FP16 not directly supported on 3510)
    reg_s32 = vf.astype(reg_a, preg_f32, round_mode=pl.VFRoundMode.CAST_TRUNC, dtype=pl.DT_INT32)
    reg_fp32_tmp = vf.astype(reg_s32, preg_f32, round_mode=pl.VFRoundMode.CAST_ROUND, dtype=pl.DT_FP32)
    reg_f16 = vf.astype(reg_fp32_tmp, preg_f32, round_mode=pl.VFRoundMode.CAST_ROUND, dtype=pl.DT_FP16)
    # Test S16→FP32: cast FP32→S16 first, then S16→FP32 (cross-width widening)
    reg_s16 = vf.astype(reg_a, preg_f32, round_mode=pl.VFRoundMode.CAST_TRUNC, dtype=pl.DT_INT16)
    reg_dst = vf.astype(reg_s16, preg_f32, dtype=pl.DT_FP32)
    vf.store_align(t_f0, reg_dst, preg_f32)
    # Test FP16→BF16: cast FP32→FP16 then FP16→BF16 then BF16→FP32 roundtrip
    reg_f16 = vf.astype(reg_a, preg_f32, round_mode=pl.VFRoundMode.CAST_ROUND, dtype=pl.DT_FP16)
    reg_bf16 = vf.astype(reg_f16, preg_f32, round_mode=pl.VFRoundMode.CAST_ROUND, dtype=pl.DT_BF16)
    reg_dst = vf.astype(reg_bf16, preg_f32, dtype=pl.DT_FP32)
    vf.store_align(t_f1, reg_dst, preg_f32)


@pl.jit()
def kernel_71_cast_cross_width(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_71_cast_cross_width_0(in_a, t_f0, t_f1)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_73_load_datablock_0(in_a, t_f0):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    # Test LoadAlign with data_copy_mode=pl.DataCopyMode.DATA_BLOCK_LOAD (vsldb)
    reg_dst = vf.load_align(in_a, preg, data_copy_mode=pl.DataCopyMode.DATA_BLOCK_LOAD, block_stride=32)
    vf.store_align(t_f0, reg_dst, preg)


@pl.jit()
def kernel_73_load_datablock(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_73_load_datablock_0(in_a, t_f0)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_79_dup_highest_hist_freq_0(in_a, t_f0, t_f1):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load_align(in_a, 0)
    # Duplicate vector-source with pos=HIGHEST
    reg_dst = vf.full(reg_a, preg, pos=pl.DuplicatePos.HIGHEST)
    vf.store_align(t_f0, reg_dst, preg)
    # Duplicate vector-source with pos=LOWEST (default)
    reg_dst = vf.full(reg_a, preg, pos=pl.DuplicatePos.LOWEST)
    vf.store_align(t_f1, reg_dst, preg)


@pl.jit()
def kernel_79_dup_highest_hist_freq(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_79_dup_highest_hist_freq_0(in_a, t_f0, t_f1)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_82_move_0(in_a, in_b, t_f0, t_f1):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load_align(in_a, 0)
    reg_b = vf.load_align(in_b, 0)
    reg_b = vf.move(reg_a, preg)
    vf.store_align(t_f0, reg_b, preg)
    src_mask = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    dst_mask = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    dst_mask = vf.move(src_mask)
    reg_dst = vf.add(reg_a, reg_a, dst_mask)
    vf.store_align(t_f1, reg_dst, preg)


@pl.jit()
def kernel_82_move(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_82_move_0(in_a, in_b, t_f0, t_f1)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_83_get_spr_movemask_0(in_a, t_f0, t_f1):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load_align(in_a, 0)
    reg_dst = vf.squeeze(reg_a, preg)
    vf.store_align(t_f0, reg_dst, preg)
    move_mask = vf.get_mask_spr(width=pl.MaskWidth.B32)
    reg_dst2 = vf.add(reg_a, reg_a, move_mask)
    vf.store_align(t_f1, reg_dst2, preg)


@pl.jit()
def kernel_83_get_spr_movemask(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_83_get_spr_movemask_0(in_a, t_f0, t_f1)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


@pl.vector_function
def _vf_kernel_84_full_reg_to_reg_0(in_a, in_b, t_f0, t_f1):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load_align(in_a, 0)
    reg_b = vf.load_align(in_b, 0)
    # Tensor mode: broadcast lowest element of reg_a to all lanes (default pos=LOWEST)
    reg_lowest = vf.full(reg_a, preg)
    vf.store_align(t_f0, reg_lowest, preg)
    # Tensor mode: broadcast highest element of reg_b to all lanes (pos=HIGHEST)
    reg_highest = vf.full(reg_b, preg, pos=pl.DuplicatePos.HIGHEST)
    vf.store_align(t_f1, reg_highest, preg)


@pl.jit()
def kernel_84_full_reg_to_reg(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_84_full_reg_to_reg_0(in_a, in_b, t_f0, t_f1)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


# Kernel 85: mem_bar new modes (VST_VST write-write, VV_ALL full vector barrier).
# Exercises the expanded MemBarMode enum; result is identity (2*a computed in two
# steps separated by barriers) so it is numerically checkable.
@pl.vector_function
def _vf_kernel_85_membar_modes_0(in_a, t_f0):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load_align(in_a, 0)
    reg_t = vf.add(reg_a, reg_a, preg)
    vf.store_align(t_f0, reg_t, preg)
    # write-write ordering between the two stores to the same tile
    vf.mem_bar(mode=pl.MemBarMode.VST_VST)
    reg_r = vf.load_align(t_f0, 0)
    vf.mem_bar(mode=pl.MemBarMode.VV_ALL)
    vf.store_align(t_f0, reg_r, preg)


@pl.jit()
def kernel_85_membar_modes(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_85_membar_modes_0(in_a, t_f0)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


# must now route to vsldb instead of silently falling back to vlds. Identity
# datablock load (block_stride laid out row-major) reproduces the source.
@pl.vector_function
def _vf_kernel_86_datablock_copy_0(in_a, t_f0):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg = vf.load_align(in_a, preg, data_copy_mode=pl.DataCopyMode.DATA_BLOCK_COPY, block_stride=32)
    vf.store_align(t_f0, reg, preg)


@pl.jit()
def kernel_86_datablock_copy(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_86_datablock_copy_0(in_a, t_f0)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


# Kernel 88: load_align with LoadDist (NORM/US/DS) for MaskReg dst.
# Loads a mask with DIST_NORM then uses it as an add predicate.
@pl.vector_function
def _vf_kernel_88_maskdist_0(in_a, t_f0):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load_align(in_a, 0)
    mreg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    mreg = vf.load_align(in_a, dist=pl.LoadDist.NORM)
    reg_dst = vf.add(reg_a, reg_a, mreg)
    vf.store_align(t_f0, reg_dst, preg)


@pl.jit()
def kernel_88_maskdist(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_88_maskdist_0(in_a, t_f0)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


# Kernel 89: astype (Cast) with the newly-added CAST_ODD round mode (-> ROUND_O).
# FP32 -> INT32 -> FP32 round-trip; smoke test that CAST_ODD compiles and produces
# a valid float result.
@pl.vector_function
def _vf_kernel_89_cast_odd_0(in_a, t_f0):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg_a = vf.load_align(in_a, 0)
    reg_i = vf.astype(reg_a, preg, dtype=pl.DT_INT32, round_mode=pl.VFRoundMode.CAST_TRUNC)
    reg_f = vf.astype(reg_i, preg, dtype=pl.DT_FP32)
    vf.store_align(t_f0, reg_f, preg)


@pl.jit()
def kernel_89_cast_odd(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_89_cast_odd_0(in_a, t_f0)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


# Kernel 90: 4-level nested VF — L0 → L1 → L2 → L3. Stresses the CallInliner's
# recursive flattening of nested VF sections across multiple levels (a single
# VF section must remain after inlining, not four physically-nested ones).
# Each level transforms t_f0 in place; result = exp(sqrt(abs(a)) + 1.0).
@pl.vector_function
def _vf_kernel_90_l3_abs(in_a, t_f0):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg = vf.load_align(in_a, 0)
    reg = vf.abs(reg, preg)
    vf.store_align(t_f0, reg, preg)


@pl.vector_function
def _vf_kernel_90_l2_sqrt(in_a, t_f0):
    _vf_kernel_90_l3_abs(in_a, t_f0)
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg = vf.load_align(t_f0, 0)
    reg = vf.sqrt(reg, preg)
    vf.store_align(t_f0, reg, preg)


@pl.vector_function
def _vf_kernel_90_l1_adds(in_a, t_f0):
    _vf_kernel_90_l2_sqrt(in_a, t_f0)
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg = vf.load_align(t_f0, 0)
    reg = vf.adds(reg, 1.0, preg)
    vf.store_align(t_f0, reg, preg)


@pl.vector_function
def _vf_kernel_90_l0_exp(in_a, t_f0):
    _vf_kernel_90_l1_adds(in_a, t_f0)
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    reg = vf.load_align(t_f0, 0)
    reg = vf.exp(reg, preg)
    vf.store_align(t_f0, reg, preg)


@pl.jit()
def kernel_90_nested_vf_4level(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_90_l0_exp(in_a, t_f0)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


# Kernel 91: bundles three newly-added VF features (smoke tests, verify codegen):
#   - arange with INT32 dst (verifies correct signed_type selection)  -> t_u0
@pl.vector_function
def _vf_kernel_91_new_feats_0(in_a, t_f0, t_f1, t_u0):
    preg = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_FP32)
    preg_u = vf.create_mask(pattern=pl.MaskPattern.ALL, dtype=pl.DT_UINT32)
    reg_a = vf.load_align(in_a, 0)
    # F1: arange UINT32 (verifies signed_type selection doesn't fall to int8)
    idx32 = vf.arange(0, dtype=pl.DT_INT32)
    vf.store_align(t_u0, idx32, preg_u)
    reg_max = vf.load_align(in_a, 0)
    reg_e = vf.exp_sub(reg_a, reg_max, preg, layout=pl.CastLayout.ONE)
    vf.store_align(t_f0, reg_e, preg)
    reg_mc = vf.muls_cast(reg_a, 2.0, preg, dtype=pl.DT_FP16, layout=pl.CastLayout.ONE)
    vf.store_align(t_f1, reg_mc, preg)


@pl.jit()
def kernel_91_new_feats(
    a: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    b: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_f1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_FP32],
    out_u0: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u1: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
    out_u2: pl.Tensor[[pl.DYNAMIC, pl.DYNAMIC], pl.DT_UINT32],
):
    tf = pl.TileType(shape=[N, M], dtype=pl.DT_FP32, target_memory=pl.MemorySpace.Vec)
    tu = pl.TileType(shape=[N, M], dtype=pl.DT_UINT32, target_memory=pl.MemorySpace.Vec)
    in_a = pl.make_tile(tf, addr=VA_IN_A)
    in_b = pl.make_tile(tf, addr=VA_IN_B)
    t_f0 = pl.make_tile(tf, addr=VA_F0)
    t_f1 = pl.make_tile(tf, addr=VA_F1)
    t_u0 = pl.make_tile(tu, addr=VA_U0)
    t_u1 = pl.make_tile(tu, addr=VA_U1)
    t_u2 = pl.make_tile(tu, addr=VA_U2)
    with pl.section_vector():
        pl.load(in_a, a, [0, 0])
        pl.load(in_b, b, [0, 0])
        pl.system.sync_src(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        pl.system.sync_dst(set_pipe=pl.PipeType.MTE2, wait_pipe=pl.PipeType.V, event_id=0)
        _vf_kernel_91_new_feats_0(in_a, t_f0, t_f1, t_u0)
        pl.system.sync_src(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.system.sync_dst(set_pipe=pl.PipeType.V, wait_pipe=pl.PipeType.MTE3, event_id=1)
        pl.store(out_f0, t_f0, [0, 0])
        pl.store(out_f1, t_f1, [0, 0])
        pl.store(out_u0, t_u0, [0, 0])
        pl.store(out_u1, t_u1, [0, 0])
        pl.store(out_u2, t_u2, [0, 0])


_KERNELS = [
    kernel_0_min_exp,
    kernel_1_abs_sqrt,
    kernel_2_bitwise,
    kernel_3_reduce_sum_max,
    kernel_4_reduce_min_relu,
    kernel_5_neg_adds,
    kernel_6_mins,
    kernel_7_maxs_lrelu,
    kernel_8_reduce_db_sum_max,
    kernel_9_reduce_db_min_pair,
    kernel_10_abssub_axpy,
    kernel_11_copy_madd,
    kernel_12_prelu_mul,
    kernel_13_shift_vec,
    kernel_14_mull,
    kernel_16_load_unalign,
    kernel_19_arange_brc,
    kernel_20_rint_loadsample,
    kernel_21_pack_squeeze_v2,
    kernel_22_cast_f32_to_s32,
    kernel_23_cast_s32_to_f32,
    kernel_24_cast_f32_to_f16,
    kernel_25_unpack_upper_lower,
    kernel_26_store_pack_intlv,
    kernel_27_duplicate,
    kernel_28_get_mask_spr,
    kernel_29_store_pack_v2,
    kernel_30_cast_f16_to_s32,
    kernel_31_load_brc_v2,
    kernel_32_postupdate,
    kernel_34_ln,
    kernel_35_rsqrt_mov,
    kernel_36_mla_mov,
    kernel_37_adif,
    kernel_38_avg_add3,
    kernel_39_selectr_max,
    kernel_40_log2_log10,
    kernel_42_cast_fp162s4_roundtrip,
    kernel_46_mask_logic,
    kernel_47_load_store_simple,
    kernel_48_log,
    kernel_49_truncate_maskgen,
    kernel_50_sub_div,
    kernel_51_muls_and_xor,
    kernel_52_shift_rights,
    kernel_53_de_interleave,
    kernel_54_pack_unpack,
    kernel_56_mul_add_dst_muls_cast,
    kernel_57_compare,
    kernel_58_cast_s42_bf16_int16,
    kernel_59_load_store_a_simple,
    kernel_60_load_store_u_align,
    kernel_61_load_unalign_post_update,
    kernel_62_scatter,
    kernel_65_update_mask,
    kernel_66_mask_or_xor_not,
    kernel_67_mask_mov_sel,
    kernel_68_mask_load_store,
    kernel_69_mask_pack_unpack,
    kernel_71_cast_cross_width,
    kernel_73_load_datablock,
    kernel_79_dup_highest_hist_freq,
    kernel_82_move,
    kernel_83_get_spr_movemask,
    kernel_84_full_reg_to_reg,
    kernel_85_membar_modes,
    kernel_86_datablock_copy,
    kernel_88_maskdist,
    kernel_89_cast_odd,
    kernel_90_nested_vf_4level,
    kernel_91_new_feats,
]


def float_to_uint32_bits(t):
    return t.view(torch.int32).to(torch.int64) & 0xFFFFFFFF


_KERNEL_MAP = {}
for _k in _KERNELS:
    _num = int(_k.__name__.split("_")[1])
    _KERNEL_MAP[_num] = _k


def _run_kernel(kernel_num, a_fp32, b_fp32, device, idx_u0=None):
    out_f0 = torch.empty([N, M], device=device, dtype=torch.float32)
    out_f1 = torch.empty([N, M], device=device, dtype=torch.float32)
    out_u0 = torch.empty([N, M], device=device, dtype=torch.int32)
    out_u1 = torch.empty([N, M], device=device, dtype=torch.int32)
    out_u2 = torch.empty([N, M], device=device, dtype=torch.int32)
    if idx_u0 is not None:
        out_u0 = idx_u0.to(torch.int32)
    _KERNEL_MAP[kernel_num](a_fp32, b_fp32, out_f0, out_f1, out_u0, out_u1, out_u2)
    torch.npu.synchronize()
    return out_f0, out_f1, out_u0, out_u1, out_u2


def _run_all_kernels(a_fp32, b_fp32, device):
    """Reach every kernel before accuracy assertions stop precompile discovery.

    Each result owns five 64-element tensors, so retaining all 75 results uses
    less than 100 KiB of tensor data. Real device launches remain sequential.
    """
    a_pos = torch.abs(a_fp32) + 0.1
    b_pos = torch.abs(b_fp32) + 0.1
    idx = torch.arange(M, device=device, dtype=torch.int32).reshape([N, M]).to(torch.uint32)
    results = {}
    for number in _KERNEL_MAP:
        a = a_pos if number in (34, 35, 40, 48, 50) else a_fp32
        b = b_pos if number == 50 else b_fp32
        results[number] = _run_kernel(number, a, b, device, idx_u0=idx if number == 62 else None)
    return results


@pytest.mark.soc("950")
@pypto.options(pass_options={"enable_slice": False})
def test_vf_basic_ops():
    device = ST_DEVICE
    torch.npu.set_device(device)
    torch.manual_seed(123)
    a_fp32 = torch.randn([N, M], device=device, dtype=torch.float32) * 2.0
    b_fp32 = torch.randn([N, M], device=device, dtype=torch.float32) * 2.0
    a_flat = a_fp32.flatten()
    a_bits = float_to_uint32_bits(a_fp32)
    b_bits = float_to_uint32_bits(b_fp32)
    db_elems = 8
    results = _run_all_kernels(a_fp32, b_fp32, device)
    f0, f1, *_ = results[0]
    torch.testing.assert_close(f0, torch.minimum(a_fp32, b_fp32), rtol=1e-5, atol=1e-5)
    torch.testing.assert_close(f1, torch.exp(a_fp32), rtol=1e-3, atol=1e-3)
    logging.info("Kernel 0 (Min, Exp) PASSED")
    f0, f1, *_ = results[1]
    torch.testing.assert_close(f0, torch.abs(a_fp32), rtol=1e-5, atol=1e-5)
    torch.testing.assert_close(f1, torch.sqrt(torch.abs(a_fp32)), rtol=1e-3, atol=1e-3)
    logging.info("Kernel 1 (Abs, Sqrt) PASSED")
    _, _, u0, u1, u2 = results[2]
    torch.testing.assert_close(u0, (a_bits | b_bits).to(torch.int32))
    torch.testing.assert_close(u1, (~a_bits & 0xFFFFFFFF).to(torch.int32))
    torch.testing.assert_close(u2, ((a_bits << 2) & 0xFFFFFFFF).to(torch.int32))
    logging.info("Kernel 2 (Or, Not, ShiftLefts) PASSED")
    f0, f1, *_ = results[3]
    torch.testing.assert_close(f0.flatten()[0], a_fp32.sum(), rtol=1e-2, atol=1e-2)
    torch.testing.assert_close(f1.flatten()[0], a_fp32.max(), rtol=1e-5, atol=1e-5)
    logging.info("Kernel 3 (ReduceSum, ReduceMax) PASSED")
    f0, f1, *_ = results[4]
    torch.testing.assert_close(f0.flatten()[0], a_fp32.min(), rtol=1e-5, atol=1e-5)
    torch.testing.assert_close(f1, torch.relu(a_fp32), rtol=1e-5, atol=1e-5)
    logging.info("Kernel 4 (ReduceMin, Relu) PASSED")
    f0, f1, *_ = results[5]
    torch.testing.assert_close(f0, -a_fp32, rtol=1e-5, atol=1e-5)
    torch.testing.assert_close(f1, a_fp32 + 3.14, rtol=1e-5, atol=1e-5)
    logging.info("Kernel 5 (Neg, Adds) PASSED")
    f0, f1, *_ = results[6]
    torch.testing.assert_close(f0, torch.minimum(a_fp32, torch.tensor(0.5, device=device)), rtol=1e-5, atol=1e-5)
    logging.info("Kernel 6 (Mins) PASSED")
    f0, f1, *_ = results[7]
    torch.testing.assert_close(f0, torch.maximum(a_fp32, torch.tensor(-0.5, device=device)), rtol=1e-5, atol=1e-5)
    torch.testing.assert_close(f1, torch.where(a_fp32 >= 0, a_fp32, a_fp32 * 0.1), rtol=1e-5, atol=1e-5)
    logging.info("Kernel 7 (Maxs, LeakyRelu) PASSED")
    f0, f1, *_ = results[8]
    torch.testing.assert_close(f0.flatten()[0], a_flat[0:db_elems].sum(), rtol=1e-4, atol=1e-4)
    torch.testing.assert_close(f1.flatten()[0], a_flat[0:db_elems].max(), rtol=1e-5, atol=1e-5)
    logging.info("Kernel 8 (ReduceSumDatablock, ReduceMaxDatablock) PASSED")
    f0, f1, *_ = results[9]
    torch.testing.assert_close(f0.flatten()[0], a_flat[0:db_elems].min(), rtol=1e-5, atol=1e-5)
    torch.testing.assert_close(f1.flatten()[0], a_flat[0] + a_flat[1], rtol=1e-4, atol=1e-4)
    logging.info("Kernel 9 (ReduceMinDatablock, PairReduceSum) PASSED")
    f0, f1, *_ = results[10]
    torch.testing.assert_close(f0, torch.abs(a_fp32 - b_fp32), rtol=1e-5, atol=1e-5)
    torch.testing.assert_close(f1, a_fp32 * 2.0 + b_fp32, rtol=1e-5, atol=1e-5)
    logging.info("Kernel 10 (AbsSub, Axpy) PASSED")
    f0, f1, *_ = results[11]
    torch.testing.assert_close(f0, a_fp32, rtol=1e-5, atol=1e-5)
    torch.testing.assert_close(f1, a_fp32 * b_fp32 + b_fp32, rtol=1e-4, atol=1e-4)
    logging.info("Kernel 11 (Copy, Madd) PASSED")
    f0, f1, *_ = results[12]
    torch.testing.assert_close(f0, torch.where(a_fp32 >= 0, a_fp32, a_fp32 * b_fp32), rtol=1e-5, atol=1e-5)
    torch.testing.assert_close(f1, a_fp32 * b_fp32, rtol=1e-5, atol=1e-5)
    logging.info("Kernel 12 (PRelu, Mul) PASSED")
    _, _, u0, u1, _ = results[13]
    assert u0.dtype == torch.int32
    assert u1.dtype == torch.int32
    logging.info("Kernel 13 (ShiftLeft, ShiftRight) PASSED")
    _, _, u0, u1, _ = results[14]
    a_u64 = float_to_uint32_bits(a_fp32)
    b_u64 = float_to_uint32_bits(b_fp32)
    product = a_u64 * b_u64
    torch.testing.assert_close(u0, (product & 0xFFFFFFFF).to(torch.int32))
    torch.testing.assert_close(u1, ((product >> 32) & 0xFFFFFFFF).to(torch.int32))
    logging.info("Kernel 14 (Mull) PASSED")
    f0, *_ = results[16]
    torch.testing.assert_close(f0, a_fp32, rtol=1e-5, atol=1e-5)
    logging.info("Kernel 16 (LoadUnalign) PASSED")
    # Kernel 19: ArangeDescend + LoadAlignBrc (codegen smoke test)
    f0, f1, *_ = results[19]
    assert f0.dtype == torch.float32
    logging.info("Kernel 19 (ArangeDescend, LoadAlignBrc) PASSED")
    # Kernel 20: Rint + LoadAlignUnpack (codegen smoke test)
    f0, f1, *_ = results[20]
    assert f1.dtype == torch.float32
    logging.info("Kernel 20 (Rint, LoadAlignUnpack) PASSED")
    # Kernel 21: SqueezeV2 + LoadAlignUnpack (codegen smoke test)
    f0, f1, *_ = results[21]
    assert f0.dtype == torch.float32
    assert f1.dtype == torch.float32
    logging.info("Kernel 21 (SqueezeV2, LoadAlignUnpack) PASSED")
    # Kernel 22: Cast DT_FP32 → DT_INT32 (truncation) → DT_FP32 roundtrip
    f0, *_ = results[22]
    expected_trunc = a_fp32.to(torch.int32).to(torch.float32)
    torch.testing.assert_close(f0, expected_trunc, rtol=1e-5, atol=1e-5)
    logging.info("Kernel 22 (Cast FP32→INT32→FP32 trunc) PASSED")
    # Kernel 23: Cast DT_FP32 → DT_INT32 (floor) → DT_FP32 roundtrip
    f0, *_ = results[23]
    expected_floor_int = torch.floor(a_fp32).to(torch.int32).to(torch.float32)
    torch.testing.assert_close(f0, expected_floor_int, rtol=1e-5, atol=1e-5)
    logging.info("Kernel 23 (Cast FP32→INT32→FP32 floor) PASSED")
    # Kernel 24: Cast DT_FP32 → DT_FP16 → DT_FP32 roundtrip
    f0, *_ = results[24]
    expected_f16_round = a_fp32.to(torch.float16).to(torch.float32)
    torch.testing.assert_close(f0, expected_f16_round, rtol=1e-3, atol=1e-3)
    logging.info("Kernel 24 (Cast FP32→FP16→FP32) PASSED")
    # Kernel 25: UnpackUpper + UnpackLower (codegen smoke test)
    _, _, u0, u1, _ = results[25]
    assert u0.dtype == torch.int32
    assert u1.dtype == torch.int32
    logging.info("Kernel 25 (UnpackUpper, UnpackLower) PASSED")
    # Kernel 26: StoreAlignPack + StoreAlignIntlv (codegen smoke test)
    f0, _, u0, *_ = results[26]
    assert f0.dtype == torch.float32
    assert u0.dtype == torch.int32
    logging.info("Kernel 26 (StoreAlignPack, StoreAlignIntlv) PASSED")
    # Kernel 27: Duplicate (scalar broadcast + vector-source broadcast)
    f0, f1, *_ = results[27]
    # f0 should be all 2.5 (scalar broadcast)
    expected_scalar = torch.full([N, M], 2.5, device=device, dtype=torch.float32)
    torch.testing.assert_close(f0, expected_scalar, rtol=1e-5, atol=1e-5)
    # f1 should be a[0] broadcast to all lanes (vector-source broadcast)
    expected_vec_brc = torch.full([N, M], a_fp32.flatten()[0].item(), device=device, dtype=torch.float32)
    torch.testing.assert_close(f1, expected_vec_brc, rtol=1e-5, atol=1e-5)
    logging.info("Kernel 27 (Duplicate scalar + vector) PASSED")
    # Kernel 28: GetMaskSprB32 (codegen smoke test)
    f0, *_ = results[28]
    assert f0.dtype == torch.float32
    logging.info("Kernel 28 (GetMaskSprB32) PASSED")
    # Kernel 29: StoreAlignPackV2 (codegen smoke test)
    f0, *_ = results[29]
    assert f0.dtype == torch.float32
    logging.info("Kernel 29 (StoreAlignPackV2) PASSED")
    # Kernel 30: Cast FP32→FP16→INT32→FP32 roundtrip (tests float_to_wider_int branch)
    f0, *_ = results[30]
    expected_f16_s32 = a_fp32.to(torch.float16).to(torch.int32).to(torch.float32)
    torch.testing.assert_close(f0, expected_f16_s32, rtol=1e-3, atol=1e-3)
    logging.info("Kernel 30 (Cast FP16→INT32→FP32) PASSED")
    # Kernel 31: LoadAlignBrcV2 in loop context (codegen smoke test)
    f0, *_ = results[31]
    assert f0.dtype == torch.float32
    logging.info("Kernel 31 (LoadAlignBrcV2 in loop) PASSED")
    # Kernel 32: Postupdate variants (BRC load + pack store with POST_UPDATE)
    f0, *_ = results[32]
    assert f0.dtype == torch.float32
    logging.info("Kernel 32 (Postupdate BRC load + pack store) PASSED")
    # Kernel 34: Ln (use positive inputs)
    a_pos = torch.abs(a_fp32) + 0.1
    f0, *_ = results[34]
    torch.testing.assert_close(f0, torch.log(a_pos), rtol=1e-3, atol=1e-3)
    logging.info("Kernel 34 (Ln) PASSED")
    # Kernel 35: Rsqrt + Copy (use positive inputs for rsqrt)
    f0, f1, *_ = results[35]
    torch.testing.assert_close(f1, a_pos, rtol=1e-5, atol=1e-5)
    logging.info("Kernel 35 (Rsqrt, Copy) PASSED")
    f0, f1, *_ = results[36]
    torch.testing.assert_close(f0, b_fp32 + a_fp32 * a_fp32, rtol=1e-4, atol=1e-4)
    torch.testing.assert_close(f1, a_fp32, rtol=1e-5, atol=1e-5)
    logging.info("Kernel 36 (Mla, Copy) PASSED")
    f0, f1, *_ = results[37]
    torch.testing.assert_close(f0, torch.abs(a_fp32 - b_fp32), rtol=1e-5, atol=1e-5)
    torch.testing.assert_close(f1, torch.abs(b_fp32 - a_fp32), rtol=1e-5, atol=1e-5)
    logging.info("Kernel 37 (AbsSub) PASSED")
    # Kernel 38: Avg + Add3
    f0, f1, *_ = results[38]
    torch.testing.assert_close(f0, (a_fp32 + b_fp32) / 2.0, rtol=1e-5, atol=1e-5)
    torch.testing.assert_close(f1, 2.0 * a_fp32 + b_fp32, rtol=1e-5, atol=1e-5)
    logging.info("Kernel 38 (Avg, Add3) PASSED")
    # Kernel 39: SelectR (vselr gather by identity index) + Max
    f0, f1, *_ = results[39]
    torch.testing.assert_close(f0, a_fp32[:, :1].expand_as(a_fp32), rtol=1e-5, atol=1e-5)
    torch.testing.assert_close(f1, torch.max(a_fp32, b_fp32), rtol=1e-5, atol=1e-5)
    logging.info("Kernel 39 (SelectR, Max) PASSED")
    # Kernel 40: Log2 + Log10 (use positive inputs)
    f0, f1, *_ = results[40]
    torch.testing.assert_close(f0, torch.log2(a_pos), rtol=1e-3, atol=1e-3)
    torch.testing.assert_close(f1, torch.log10(a_pos), rtol=1e-3, atol=1e-3)
    logging.info("Kernel 40 (Log2, Log10) PASSED")
    f0, *_ = results[42]
    assert f0.dtype == torch.float32
    logging.info("Kernel 42 (CastFp162S4, CastS42Fp16) PASSED")
    f0, *_ = results[46]
    assert f0.dtype == torch.float32
    logging.info("Kernel 46 (MaskAnd/Or/Xor/Not) PASSED")
    f0, *_ = results[47]
    assert f0.dtype == torch.float32
    logging.info("Kernel 47 (LoadSimple, StoreSimple) PASSED")
    a_pos = torch.abs(a_fp32) + 0.1
    f0, *_ = results[48]
    torch.testing.assert_close(f0, torch.log(a_pos), rtol=1e-3, atol=1e-3)
    logging.info("Kernel 48 (Log/vln) PASSED")
    f0, f1, *_ = results[49]
    torch.testing.assert_close(f0, torch.trunc(a_fp32), rtol=1e-5, atol=1e-5)
    # mask depends on bit 0 of b's IEEE754 repr — just verify codegen produces valid output
    assert f1.shape == a_fp32.shape and f1.dtype == torch.float32
    logging.info("Kernel 49 (Truncate, MaskGenWithRegTensor/Select) PASSED")
    # Kernel 50: Sub, Div (use positive inputs for div)
    a_pos = torch.abs(a_fp32) + 0.1
    b_pos = torch.abs(b_fp32) + 0.1
    f0, f1, *_ = results[50]
    torch.testing.assert_close(f0, a_pos - b_pos, rtol=1e-5, atol=1e-5)
    torch.testing.assert_close(f1, a_pos / b_pos, rtol=1e-3, atol=1e-3)
    logging.info("Kernel 50 (Sub, Div) PASSED")
    # Kernel 51: Muls, And, Xor
    f0, _, u0, u1, _ = results[51]
    torch.testing.assert_close(f0, a_fp32 * 2.5, rtol=1e-5, atol=1e-5)
    torch.testing.assert_close(u0, (a_bits & b_bits).to(torch.int32))
    torch.testing.assert_close(u1, (a_bits ^ b_bits).to(torch.int32))
    logging.info("Kernel 51 (Muls, And, Xor) PASSED")
    # Kernel 52: ShiftRights (scalar right shift)
    _, _, u0, *_ = results[52]
    torch.testing.assert_close(u0, ((a_bits >> 2) & 0xFFFFFFFF).to(torch.int32))
    logging.info("Kernel 52 (ShiftRights) PASSED")
    # Kernel 53: DeInterleave (roundtrip: interleave then de_interleave)
    f0, f1, *_ = results[53]
    torch.testing.assert_close(f0, a_fp32, rtol=1e-5, atol=1e-5)
    torch.testing.assert_close(f1, b_fp32, rtol=1e-5, atol=1e-5)
    logging.info("Kernel 53 (DeInterleave roundtrip) PASSED")
    # Kernel 54: Pack, Unpack (smoke test)
    _, _, u0, *_ = results[54]
    assert u0.dtype == torch.int32
    logging.info("Kernel 54 (Pack, Unpack) PASSED")
    # Kernel 56: MulAddDst, MulsCast
    f0, f1, *_ = results[56]
    torch.testing.assert_close(f0, b_fp32 * a_fp32 + b_fp32, rtol=1e-4, atol=1e-4)
    torch.testing.assert_close(f1, (a_fp32 * 2.0).to(torch.float16).to(torch.float32), rtol=1e-3, atol=1e-3)
    logging.info("Kernel 56 (MulAddDst, MulsCast) PASSED")
    # Kernel 57: Compare (vector-vector GT, select a where a>b else b = max(a,b))
    f0, *_ = results[57]
    torch.testing.assert_close(f0, torch.max(a_fp32, b_fp32), rtol=1e-5, atol=1e-5)
    logging.info("Kernel 57 (Compare) PASSED")
    # Kernel 58: CastS42Bf16, CastS42Int16 (smoke test)
    f0, f1, *_ = results[58]
    assert f0.dtype == torch.float32
    assert f1.dtype == torch.float32
    logging.info("Kernel 58 (CastS42Bf16, CastS42Int16) PASSED")
    # Kernel 59: LoadASimple, StoreASimple (2*a)
    f0, *_ = results[59]
    torch.testing.assert_close(f0, a_fp32 * 2.0, rtol=1e-5, atol=1e-5)
    logging.info("Kernel 59 (LoadASimple, StoreASimple) PASSED")
    # Kernel 60: LoadUAlign, StoreUAlign (2*a)
    f0, *_ = results[60]
    torch.testing.assert_close(f0, a_fp32 * 2.0, rtol=1e-5, atol=1e-5)
    logging.info("Kernel 60 (LoadUAlign, StoreUAlign) PASSED")
    # Kernel 61: LoadUnalignPostUpdate (identity load)
    f0, *_ = results[61]
    torch.testing.assert_close(f0, a_fp32, rtol=1e-5, atol=1e-5)
    logging.info("Kernel 61 (LoadUnalignPostUpdate) PASSED")
    # Kernel 62: Scatter (identity scatter with loaded index)
    f0, *_ = results[62]
    torch.testing.assert_close(f0, a_fp32, rtol=1e-5, atol=1e-5)
    logging.info("Kernel 62 (Scatter) PASSED")
    # Kernel 65: UpdateMask (smoke test)
    f0, *_ = results[65]
    assert f0.dtype == torch.float32
    logging.info("Kernel 65 (UpdateMask) PASSED")
    # Kernel 66: MaskOr, MaskXor (smoke test — stored with mask, not ALL)
    f0, f1, *_ = results[66]
    assert f0.dtype == torch.float32
    assert f1.dtype == torch.float32
    logging.info("Kernel 66 (MaskOr, MaskXor) PASSED")
    # Kernel 67: MaskMov, MaskSel (smoke test)
    f0, f1, *_ = results[67]
    assert f0.dtype == torch.float32
    assert f1.dtype == torch.float32
    logging.info("Kernel 67 (MaskMov, MaskSel) PASSED")
    # Kernel 68: MaskLoad, MaskStore (mask roundtrip via UB, stored with ALL preg)
    f0, *_ = results[68]
    torch.testing.assert_close(
        f0,
        torch.where(a_fp32 >= 0, torch.abs(a_fp32), torch.tensor(0.0, device=device)),
        rtol=1e-5,
        atol=1e-5,
    )
    logging.info("Kernel 68 (MaskLoad, MaskStore) PASSED")
    # Kernel 69: MaskPack, MaskUnpack (smoke test)
    f0, *_ = results[69]
    assert f0.dtype == torch.float32
    logging.info("Kernel 69 (MaskPack, MaskUnpack) PASSED")
    # Kernel 71: Cast cross-width (S16→FP32, S32→FP16, FP16→BF16)
    f0, f1, *_ = results[71]
    # f0: FP32→S16→FP32 roundtrip (truncate to int16 range then back)
    expected_s16 = torch.clamp(torch.trunc(a_fp32), -32768, 32767).to(torch.float32)
    torch.testing.assert_close(f0, expected_s16, rtol=1e-5, atol=1.0)
    # f1: FP32→FP16→BF16→FP32 roundtrip (double precision loss)
    assert f1.dtype == torch.float32
    logging.info("Kernel 71 (Cast cross-width: S16/DT_FP32, S32/DT_FP16, DT_FP16/DT_BF16) PASSED")
    # Kernel 73: LoadAlign DATA_BLOCK_LOAD (vsldb codegen smoke test)
    f0, *_ = results[73]
    assert f0.dtype == torch.float32
    logging.info("Kernel 73 (LoadAlign DATA_BLOCK_LOAD/vsldb) PASSED")
    f0, f1, *_ = results[79]
    # f0: broadcast HIGHEST element of a_fp32 to all lanes
    expected_highest = torch.full([N, M], a_fp32.flatten()[-1].item(), device=device, dtype=torch.float32)
    torch.testing.assert_close(f0, expected_highest, rtol=1e-5, atol=1e-5)
    # f1: broadcast LOWEST element of a_fp32 to all lanes
    expected_lowest = torch.full([N, M], a_fp32.flatten()[0].item(), device=device, dtype=torch.float32)
    torch.testing.assert_close(f1, expected_lowest, rtol=1e-5, atol=1e-5)
    logging.info("Kernel 79 (Duplicate pos=HIGHEST/LOWEST) PASSED")
    # Kernel 82: Move — RegTensor move (masked) + MaskReg move (unmasked)
    f0, f1, *_ = results[82]
    torch.testing.assert_close(f0, a_fp32, rtol=1e-5, atol=1e-5)
    torch.testing.assert_close(f1, a_fp32 + a_fp32, rtol=1e-5, atol=1e-5)
    logging.info("Kernel 82 (Move RegTensor + MaskReg) PASSED")
    # Kernel 83: GetSpr (get_ar) + MoveMask (get_mask_spr)
    f0, f1, *_ = results[83]
    assert f0.dtype == torch.float32
    assert f1.dtype == torch.float32
    logging.info("Kernel 83 (GetSpr + MoveMask) PASSED")
    # Kernel 84: Full (Duplicate) reg-to-reg broadcast — pos=LOWEST + pos=HIGHEST
    f0, f1, *_ = results[84]
    # f0: broadcast lowest element of a_fp32 to all lanes
    expected_lowest = torch.full([N, M], a_fp32.flatten()[0].item(), device=device, dtype=torch.float32)
    torch.testing.assert_close(f0, expected_lowest, rtol=1e-5, atol=1e-5)
    # f1: broadcast highest element of b_fp32 to all lanes
    expected_highest = torch.full([N, M], b_fp32.flatten()[-1].item(), device=device, dtype=torch.float32)
    torch.testing.assert_close(f1, expected_highest, rtol=1e-5, atol=1e-5)
    logging.info("Kernel 84 (Full reg-to-reg LOWEST + HIGHEST) PASSED")
    f0, *_ = results[85]
    torch.testing.assert_close(f0, a_fp32 * 2.0, rtol=1e-5, atol=1e-5)
    logging.info("Kernel 85 (MemBar VST_VST + VV_ALL) PASSED")
    f0, *_ = results[86]
    assert f0.dtype == torch.float32
    logging.info("Kernel 86 (LoadAlign DATA_BLOCK_COPY) PASSED")
    # Kernel 88: load_align with LoadDist.NORM for MaskReg dst
    f0, *_ = results[88]
    assert f0.dtype == torch.float32
    logging.info("Kernel 88 (LoadDist NORM) PASSED")
    # Kernel 89: astype with CAST_ODD round mode (smoke test compiles + valid float)
    f0, *_ = results[89]
    assert f0.dtype == torch.float32
    logging.info("Kernel 89 (Cast CAST_ODD) PASSED")
    # Kernel 90: 4-level nested VF — result = exp(sqrt(abs(a)) + 1.0)
    f0, *_ = results[90]
    torch.testing.assert_close(f0, torch.exp(torch.sqrt(torch.abs(a_fp32)) + 1.0), rtol=1e-3, atol=1e-3)
    logging.info("Kernel 90 (4-level nested VF) PASSED")
    f0, f1, u0, *_ = results[91]
    assert f0.dtype == torch.float32 and f1.dtype == torch.float32 and u0.dtype == torch.int32
    logging.info("Kernel 91 (arange u32 / exp_sub / muls_cast layout=ONE) PASSED")
    logging.info("All VF basic ops tests PASSED!")


if __name__ == "__main__":
    logging.basicConfig(level=logging.INFO, format="%(message)s")
    test_vf_basic_ops()
