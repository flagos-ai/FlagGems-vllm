# Copyright 2026 FlagOS Contributors
#
# Licensed under the Apache License, Version 2.0 (the "License");
# you may not use this file except in compliance with the License.
# You may obtain a copy of the License at
#
#     http://www.apache.org/licenses/LICENSE-2.0
#
# Unless required by applicable law or agreed to in writing, software
# distributed under the License is distributed on an "AS IS" BASIS,
# WITHOUT WARRANTIES OR CONDITIONS OF ANY KIND, either express or implied.
# See the License for the specific language governing permissions and
# limitations under the License.

import pytest
import torch
import triton
import triton.language as tl

import flaggems_vllm
from flaggems_vllm import unpack_seq_triton

from . import base

# =============================================================================
# vLLM availability check
# =============================================================================

try:
    from vllm.v1.attention.ops.common import unpack_seq_triton as vllm_unpack_seq

    HAS_VLLM = True
except ImportError:
    HAS_VLLM = False


# =============================================================================
# FP8 availability check
# =============================================================================


@triton.jit
def _fp8_check_kernel(x, y):
    val = tl.load(x)
    tl.store(y, val)


try:
    FP8_DTYPE = torch.float8_e4m3fn
    x1 = torch.randn(1, dtype=torch.float32, device=flaggems_vllm.device).to(FP8_DTYPE)
    y1 = torch.empty([1], dtype=FP8_DTYPE, device=flaggems_vllm.device)
    _fp8_check_kernel[(1,)](x1, y1)
    FP8_AVAILABLE = True
except Exception:
    try:
        FP8_DTYPE = torch.float8_e5m2
        x2 = torch.randn(1, dtype=torch.float32, device=flaggems_vllm.device).to(
            FP8_DTYPE
        )
        y2 = torch.empty([1], dtype=FP8_DTYPE, device=flaggems_vllm.device)
        _fp8_check_kernel[(1,)](x2, y2)
        FP8_AVAILABLE = True
    except Exception:
        FP8_DTYPE = None
        FP8_AVAILABLE = False


# =============================================================================
# Benchmark shapes: (N, D, B, lengths_list)
# =============================================================================

UNPACK_BENCH_SHAPES = [
    (512, 64, 5, [64, 128, 64, 128, 128]),
    (4096, 128, 4, [1024, 1024, 1024, 1024]),
    (8192, 256, 5, [1024, 2048, 1024, 2048, 2048]),
    (2048, 512, 4, [512, 512, 512, 512]),
    (16384, 64, 8, [2048] * 8),
    (1024, 1024, 4, [256] * 4),
    (2048, 2048, 512, [4] * 512),
    (4094, 1024, 1024, [4] * 1024),
    (8192, 1024, 1024, [8] * 1024),
]

FP8_BENCH_SHAPES = [
    (512, 64, 5, [64, 128, 64, 128, 128]),
    (4096, 128, 4, [1024, 1024, 1024, 1024]),
    (2048, 512, 4, [512, 512, 512, 512]),
    (2048, 2048, 512, [4] * 512),
    (4094, 1024, 1024, [4] * 1024),
    (8192, 1024, 1024, [8] * 1024),
]


# =============================================================================
# Custom Benchmark class — unpack_seq (float dtypes)
# =============================================================================


class UnpackSeqBenchmark(base.Benchmark):
    DEFAULT_DTYPES = [torch.float16, torch.float32, torch.bfloat16]

    def __init__(self, op_name, torch_op, dtypes):
        super().__init__(op_name=op_name, torch_op=torch_op, dtypes=dtypes)

    def set_shapes(self, shape_file_path=None):
        self.shapes = UNPACK_BENCH_SHAPES

    def get_input_iter(self, cur_dtype):
        for config in self.shapes:
            yield from self._unpack_input_fn(config, cur_dtype)

    def _unpack_input_fn(self, config, dtype):
        N, D, B, lengths_list = config
        Lmax = max(lengths_list)
        device = flaggems_vllm.device
        lengths = torch.tensor(lengths_list, dtype=torch.int32, device=device)
        packed = torch.randn(B, Lmax, D, dtype=dtype, device=device)
        yield packed, lengths


# =============================================================================
# Custom Benchmark class — unpack_seq (FP8)
# =============================================================================


class UnpackSeqFP8Benchmark(base.Benchmark):
    def __init__(self, op_name, torch_op, dtypes):
        super().__init__(op_name=op_name, torch_op=torch_op, dtypes=dtypes)

    def set_shapes(self, shape_file_path=None):
        self.shapes = FP8_BENCH_SHAPES

    def get_input_iter(self, cur_dtype):
        del cur_dtype
        for config in self.shapes:
            yield from self._fp8_input_fn(config)

    def _fp8_input_fn(self, config):
        N, D, B, lengths_list = config
        Lmax = max(lengths_list)
        device = flaggems_vllm.device
        lengths = torch.tensor(lengths_list, dtype=torch.int32, device=device)
        packed = torch.randn(B, Lmax, D, dtype=torch.float32, device=device) * 0.1
        packed_fp8 = packed.to(FP8_DTYPE)
        yield packed_fp8, lengths


@pytest.mark.unpack_seq_triton
@pytest.mark.skipif(
    not HAS_VLLM,
    reason="requires vLLM to be installed for reference comparison",
)
def test_unpack_seq():
    bench = UnpackSeqBenchmark(
        op_name="unpack_seq_triton",
        torch_op=vllm_unpack_seq,
        dtypes=[torch.float16, torch.float32, torch.bfloat16],
    )
    bench.set_gems(unpack_seq_triton)
    bench.run()


@pytest.mark.unpack_seq_triton
@pytest.mark.skipif(
    not HAS_VLLM,
    reason="requires vLLM to be installed for reference comparison",
)
@pytest.mark.skipif(
    not FP8_AVAILABLE,
    reason="FP8 is not supported on the current device",
)
def test_unpack_seq_fp8():
    bench = UnpackSeqFP8Benchmark(
        op_name="unpack_seq_triton",
        torch_op=vllm_unpack_seq,
        dtypes=[FP8_DTYPE],
    )
    bench.set_gems(unpack_seq_triton)
    bench.run()


# =============================================================================
# Custom Benchmark class — unpack_seq (INT8)
# =============================================================================


class UnpackSeqINT8Benchmark(base.Benchmark):
    def __init__(self, op_name, torch_op, dtypes):
        super().__init__(op_name=op_name, torch_op=torch_op, dtypes=dtypes)

    def set_shapes(self, shape_file_path=None):
        self.shapes = UNPACK_BENCH_SHAPES

    def get_input_iter(self, cur_dtype):
        del cur_dtype
        for config in self.shapes:
            yield from self._int8_input_fn(config)

    def _int8_input_fn(self, config):
        N, D, B, lengths_list = config
        Lmax = max(lengths_list)
        device = flaggems_vllm.device
        lengths = torch.tensor(lengths_list, dtype=torch.int32, device=device)
        # unpack_seq_triton has no dtype-specific padding branch (pure
        # load/store copy), so the padding region's contents don't matter
        # for this benchmark -- only the valid-token copy is measured.
        packed = torch.randint(-128, 128, (B, Lmax, D), dtype=torch.int8, device=device)
        yield packed, lengths


@pytest.mark.unpack_seq_triton
@pytest.mark.skipif(
    not HAS_VLLM,
    reason="requires vLLM to be installed for reference comparison",
)
def test_unpack_seq_int8():
    bench = UnpackSeqINT8Benchmark(
        op_name="unpack_seq_triton",
        torch_op=vllm_unpack_seq,
        dtypes=[torch.int8],
    )
    bench.set_gems(unpack_seq_triton)
    bench.run()
