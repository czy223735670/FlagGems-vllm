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

"""Shared baseline contract for the mHC ``hc_expand`` operator.

Functional tests use vLLM's PyTorch ``hc_expand`` implementation. vLLM's NVIDIA
Triton implementation is the performance baseline used by the benchmark suite.
"""

import importlib

import torch

OP_NAME = "hc_expand"
DTYPES = [torch.bfloat16, torch.float32]
IS_INPLACE = False
INPUT_LAYOUTS = (
    "contiguous",
    "strided",
    "transposed",
    "row_padded",
    "column_stride_3",
    "broadcast_h",
    "storage_offset",
)

BENCHMARK_SHAPES = [
    (0, 17, 4),
    (1, 513, 1),
    (7, 17, 8),
    (33, 5137, 4),
    (8192, 5120, 4),
    (1, 5120, 4),
    (16, 5120, 4),
    (256, 5120, 4),
    (1024, 5120, 4),
    (4096, 5120, 4),
    (16384, 5120, 4),
    (32768, 5120, 4),
    (1025, 5120, 4),
    (8193, 5120, 4),
]

FUNCTIONAL_SHAPES = [
    *BENCHMARK_SHAPES,
    (2, 5120, 8),
    (4, 5120, 2),
    (8, 5120, 3),
    (32, 5120, 5),
    (64, 5120, 6),
    (128, 5120, 7),
    (512, 5120, 9),
    (2048, 5120, 16),
    (1, 5120, 2),
    (7, 5120, 3),
    (33, 5137, 5),
    (1025, 5120, 6),
    (8193, 5120, 7),
]

NATIVE_UNAVAILABLE_REASON = None


def _resolve(module_name, attr):
    global NATIVE_UNAVAILABLE_REASON
    try:
        module = importlib.import_module(module_name)
        op = getattr(module, attr)
    except (ImportError, AttributeError, RuntimeError, OSError) as exc:
        NATIVE_UNAVAILABLE_REASON = f"{module_name}.{attr}: {exc}"
        return None
    return op if callable(op) else None


def native():
    """Return vLLM's NVIDIA Triton implementation used as the perf baseline."""
    return _resolve("vllm.models.deepseek_v41.nvidia.ops.mhc", "hc_expand")


def torch_reference():
    """Return vLLM's PyTorch implementation used as the correctness oracle."""
    return _resolve("vllm.model_executor.layers.mhc", "hc_expand")


def grid():
    return [
        {
            "num_tokens": num_tokens,
            "hidden_size": hidden_size,
            "hc_mult": hc_mult,
        }
        for num_tokens, hidden_size, hc_mult in BENCHMARK_SHAPES
    ]


def build_inputs(
    binding,
    dtype,
    device,
    *,
    strided=False,
    layout=None,
    special_values=True,
):
    num_tokens = binding["num_tokens"]
    hidden_size = binding["hidden_size"]
    hc_mult = binding["hc_mult"]

    if layout is None:
        layout = "strided" if strided else "contiguous"

    if layout == "contiguous":
        x = torch.randn(
            num_tokens,
            hidden_size,
            dtype=dtype,
            device=device,
        )
    elif layout == "strided":
        # Both axes are non-unit stride: (2 * hidden + 1, 2).
        storage = torch.randn(
            num_tokens,
            2 * hidden_size + 1,
            dtype=dtype,
            device=device,
        )
        x = storage[:, 1::2]
    elif layout == "transposed":
        # Row stride 1, column stride num_tokens.
        storage = torch.randn(
            hidden_size,
            num_tokens,
            dtype=dtype,
            device=device,
        )
        x = storage.t()
    elif layout == "row_padded":
        # Contiguous columns with padding between rows.
        storage = torch.randn(
            num_tokens,
            hidden_size + 7,
            dtype=dtype,
            device=device,
        )
        x = storage[:, :hidden_size]
    elif layout == "column_stride_3":
        # Non-unit row and column strides.
        storage = torch.randn(
            num_tokens,
            3 * hidden_size + 5,
            dtype=dtype,
            device=device,
        )
        x = storage[:, : 3 * hidden_size : 3]
    elif layout == "broadcast_h":
        # Every logical row broadcasts a single value across H.
        storage = torch.randn(
            num_tokens,
            1,
            dtype=dtype,
            device=device,
        )
        x = storage.expand(num_tokens, hidden_size)
    elif layout == "storage_offset":
        # Non-zero storage offset with contiguous inner columns.
        storage = torch.randn(
            num_tokens,
            hidden_size + 3,
            dtype=dtype,
            device=device,
        )
        x = storage[:, 2 : 2 + hidden_size]
    else:
        raise ValueError(f"unsupported input layout: {layout!r}")

    # Bitwise validation must also cover non-finite values and signed zero.
    if special_values and num_tokens and hidden_size:
        x[0, 0] = float("nan")
        x[0, -1] = -0.0
        if hidden_size > 1:
            x[0, 1] = float("inf")
        if hidden_size > 2:
            x[0, 2] = float("-inf")

    return (x, hc_mult), {}


def key_shape(binding):
    return (
        f"tokens{binding['num_tokens']}_hidden{binding['hidden_size']}_"
        f"hc{binding['hc_mult']}"
    )


def config(binding, dtype, *, layout="contiguous"):
    num_tokens = binding["num_tokens"]
    hidden_size = binding["hidden_size"]
    hc_mult = binding["hc_mult"]
    stride = {
        "contiguous": [hidden_size, 1],
        "strided": [2 * hidden_size + 1, 2],
        "transposed": [1, num_tokens],
        "row_padded": [hidden_size + 7, 1],
        "column_stride_3": [3 * hidden_size + 5, 3],
        "broadcast_h": [1, 0],
        "storage_offset": [hidden_size + 3, 1],
    }.get(layout)
    if stride is None:
        raise ValueError(f"unsupported input layout: {layout!r}")
    return {
        "inputs": {
            "x": {
                "shape": [num_tokens, hidden_size],
                "dtype": str(dtype),
                "stride": stride,
            },
            "hc_mult": {"scalar": hc_mult},
        },
        "outputs": {
            "out": {
                "shape": [num_tokens, hc_mult, hidden_size],
                "dtype": str(dtype),
                "layout": "contiguous",
            }
        },
        "dims": dict(binding),
    }
