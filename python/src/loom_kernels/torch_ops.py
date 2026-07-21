"""PyTorch custom-operator registration for Loom Kernels."""

from __future__ import annotations

import math

import torch

from ._native import (
    launch_add_rms_norm,
    launch_rms_norm_dynamic_fp8,
    launch_silu_and_mul,
    launch_silu_and_mul_dynamic_fp8,
)
from ._torch_extension import load_torch_extension


_DTYPE_NAMES = {
    torch.float32: "f32",
    torch.float16: "f16",
    torch.bfloat16: "bf16",
}


def supports_add_rms_norm(
    input_tensor: torch.Tensor,
    residual: torch.Tensor,
    weight: torch.Tensor | None,
    epsilon: float,
    variance_size: int | None = None,
) -> bool:
    """Shape/dtype predicate shared with the vLLM IR provider."""
    del epsilon
    return bool(
        variance_size is None
        and weight is not None
        and input_tensor.device.type == "cuda"
        and residual.device == input_tensor.device
        and weight.device == input_tensor.device
        and input_tensor.dtype in _DTYPE_NAMES
        and residual.dtype == input_tensor.dtype
        and weight.dtype == input_tensor.dtype
        and input_tensor.dim() >= 1
        and input_tensor.shape == residual.shape
        and weight.dim() == 1
        and weight.shape[0] == input_tensor.shape[-1]
        and input_tensor.is_contiguous()
        and residual.is_contiguous()
        and weight.is_contiguous()
    )


def supports_vllm_add_rms_norm(
    input_tensor: torch.Tensor,
    residual: torch.Tensor,
    weight: torch.Tensor | None,
    epsilon: float,
    variance_size: int | None = None,
) -> bool:
    """Minimal hot-path predicate for tensors already governed by vLLM IR."""
    del epsilon
    return bool(
        variance_size is None
        and weight is not None
        and input_tensor.dtype in _DTYPE_NAMES
        and residual.dtype == input_tensor.dtype
        and weight.dtype == input_tensor.dtype
        and input_tensor.is_contiguous()
        and residual.is_contiguous()
        and weight.is_contiguous()
    )


def supports_rms_norm_dynamic_fp8(
    input_tensor: torch.Tensor,
    weight: torch.Tensor | None,
    epsilon: float,
) -> bool:
    """Return whether Loom can fuse RMSNorm with per-token FP8 quantization."""
    return bool(
        weight is not None
        and math.isfinite(epsilon)
        and epsilon > 0.0
        and input_tensor.device.type == "cuda"
        and weight.device == input_tensor.device
        and input_tensor.dtype in _DTYPE_NAMES
        and weight.dtype == input_tensor.dtype
        and input_tensor.dim() >= 1
        and input_tensor.numel() > 0
        and weight.dim() == 1
        and weight.shape[0] == input_tensor.shape[-1]
        and input_tensor.is_contiguous()
        and weight.is_contiguous()
    )


def supports_silu_and_mul(input_tensor: torch.Tensor) -> bool:
    """Return whether Loom supports split-half SiLU-and-Mul for this input."""
    return bool(
        input_tensor.device.type == "cuda"
        and input_tensor.dtype in _DTYPE_NAMES
        and input_tensor.dim() >= 1
        and input_tensor.numel() > 0
        and input_tensor.shape[-1] % 2 == 0
        and input_tensor.is_contiguous()
    )


def supports_silu_and_mul_dynamic_fp8(
    input_tensor: torch.Tensor, group_size: int
) -> bool:
    """Return whether Loom supports fused SwiGLU and block FP8."""
    if input_tensor.dim() < 1 or input_tensor.shape[-1] % 2 != 0:
        return False
    width = input_tensor.shape[-1] // 2
    return bool(
        input_tensor.device.type == "cuda"
        and input_tensor.dtype in (torch.float16, torch.bfloat16)
        and input_tensor.numel() > 0
        and group_size in (64, 128)
        and width % group_size == 0
        and input_tensor.is_contiguous()
    )


def _validate(
    input_tensor: torch.Tensor,
    residual: torch.Tensor,
    weight: torch.Tensor,
    epsilon: float,
) -> tuple[str, int, int]:
    if not supports_add_rms_norm(input_tensor, residual, weight, epsilon):
        raise ValueError(
            "Loom Add+RMSNorm requires same-device contiguous CUDA tensors, "
            "matching F32/FP16/BF16 dtypes and a 1D hidden-size weight"
        )
    if not math.isfinite(epsilon) or epsilon <= 0.0:
        raise ValueError(f"epsilon must be finite and positive, got {epsilon}")
    if input_tensor.requires_grad or residual.requires_grad or weight.requires_grad:
        raise ValueError("Loom Add+RMSNorm is an inference-only operator")

    hidden_size = input_tensor.shape[-1]
    rows = input_tensor.numel() // hidden_size
    if rows > 0xFFFF_FFFF or hidden_size > 0xFFFF_FFFF:
        raise ValueError("tensor shape exceeds the Loom CUDA ABI")
    return _DTYPE_NAMES[input_tensor.dtype], rows, hidden_size


def _validate_dynamic_fp8_inputs(
    input_tensor: torch.Tensor,
    weight: torch.Tensor,
    epsilon: float,
) -> tuple[str, int, int]:
    if not supports_rms_norm_dynamic_fp8(input_tensor, weight, epsilon):
        raise ValueError(
            "Loom RMSNorm+FP8 requires same-device contiguous CUDA tensors, "
            "matching F32/FP16/BF16 dtypes and a 1D hidden-size weight"
        )
    if input_tensor.requires_grad or weight.requires_grad:
        raise ValueError("Loom RMSNorm+FP8 is an inference-only operator")

    hidden_size = input_tensor.shape[-1]
    rows = input_tensor.numel() // hidden_size
    if rows > 0xFFFF_FFFF or hidden_size > 0xFFFF_FFFF:
        raise ValueError("tensor shape exceeds the Loom CUDA ABI")
    return _DTYPE_NAMES[input_tensor.dtype], rows, hidden_size


def _validate_dynamic_fp8_buffers(
    input_tensor: torch.Tensor,
    weight: torch.Tensor,
    output: torch.Tensor,
    scales: torch.Tensor,
    epsilon: float,
) -> tuple[str, int, int]:
    dtype, rows, hidden_size = _validate_dynamic_fp8_inputs(
        input_tensor, weight, epsilon
    )
    if (
        output.device != input_tensor.device
        or output.dtype != torch.float8_e4m3fn
        or output.shape != input_tensor.shape
        or not output.is_contiguous()
    ):
        raise ValueError(
            "Loom RMSNorm+FP8 output must be a same-device contiguous "
            "torch.float8_e4m3fn tensor matching the input shape"
        )
    if (
        scales.device != input_tensor.device
        or scales.dtype != torch.float32
        or scales.shape != (rows, 1)
        or not scales.is_contiguous()
    ):
        raise ValueError(
            "Loom RMSNorm+FP8 scales must be a same-device contiguous F32 "
            "tensor with shape [rows, 1]"
        )
    return dtype, rows, hidden_size


def _validate_silu_and_mul_input(
    input_tensor: torch.Tensor,
) -> tuple[str, int, int]:
    if not supports_silu_and_mul(input_tensor):
        raise ValueError(
            "Loom SiLU-and-Mul requires a non-empty contiguous F32/FP16/BF16 "
            "CUDA tensor with an even last dimension"
        )
    if input_tensor.requires_grad:
        raise ValueError("Loom SiLU-and-Mul is an inference-only operator")

    width = input_tensor.shape[-1] // 2
    rows = input_tensor.numel() // input_tensor.shape[-1]
    if rows > 0xFFFF_FFFF or width > 0xFFFF_FFFF:
        raise ValueError("tensor shape exceeds the Loom CUDA ABI")
    return _DTYPE_NAMES[input_tensor.dtype], rows, width


def _validate_silu_and_mul_buffers(
    input_tensor: torch.Tensor,
    output: torch.Tensor,
) -> tuple[str, int, int]:
    dtype, rows, width = _validate_silu_and_mul_input(input_tensor)
    expected_shape = (*input_tensor.shape[:-1], width)
    if (
        output.device != input_tensor.device
        or output.dtype != input_tensor.dtype
        or output.shape != expected_shape
        or not output.is_contiguous()
    ):
        raise ValueError(
            "Loom SiLU-and-Mul output must be a same-device contiguous tensor "
            "with matching dtype and half the input last dimension"
        )
    return dtype, rows, width


def _validate_silu_and_mul_dynamic_fp8_input(
    input_tensor: torch.Tensor,
    group_size: int,
) -> tuple[str, int, int, int]:
    if not supports_silu_and_mul_dynamic_fp8(input_tensor, group_size):
        raise ValueError(
            "Loom SiLU-and-Mul+FP8 requires a non-empty contiguous FP16/BF16 "
            "CUDA tensor, group size 64 or 128, and a divisible output width"
        )
    if input_tensor.requires_grad:
        raise ValueError("Loom SiLU-and-Mul+FP8 is an inference-only operator")

    width = input_tensor.shape[-1] // 2
    rows = input_tensor.numel() // input_tensor.shape[-1]
    group_count = width // group_size
    if rows > 0xFFFF_FFFF or width > 0xFFFF_FFFF:
        raise ValueError("tensor shape exceeds the Loom CUDA ABI")
    return _DTYPE_NAMES[input_tensor.dtype], rows, width, group_count


def _validate_silu_and_mul_dynamic_fp8_buffers(
    input_tensor: torch.Tensor,
    output: torch.Tensor,
    scales: torch.Tensor,
    group_size: int,
) -> tuple[str, int, int]:
    dtype, rows, width, group_count = _validate_silu_and_mul_dynamic_fp8_input(
        input_tensor, group_size
    )
    expected_shape = (*input_tensor.shape[:-1], width)
    if (
        output.device != input_tensor.device
        or output.dtype != torch.float8_e4m3fn
        or output.shape != expected_shape
        or not output.is_contiguous()
    ):
        raise ValueError(
            "Loom SiLU-and-Mul+FP8 output must be a same-device contiguous "
            "torch.float8_e4m3fn tensor with half the input last dimension"
        )
    if (
        scales.device != input_tensor.device
        or scales.dtype != torch.float32
        or scales.shape != (rows, group_count)
        or not scales.is_contiguous()
    ):
        raise ValueError(
            "Loom SiLU-and-Mul+FP8 scales must be same-device contiguous F32 "
            "with shape [rows, width / group_size]"
        )
    return dtype, rows, width


_EXTENSION_PATH = load_torch_extension()

if _EXTENSION_PATH is None:

    @torch.library.custom_op(
        "loom_kernels::add_rms_norm_mut",
        mutates_args={"input_tensor", "residual"},
        device_types="cuda",
    )
    def _add_rms_norm_mut(
        input_tensor: torch.Tensor,
        residual: torch.Tensor,
        weight: torch.Tensor,
        epsilon: float,
    ) -> None:
        dtype, rows, hidden_size = _validate(input_tensor, residual, weight, epsilon)
        device_index = input_tensor.device.index
        if device_index is None:
            device_index = torch.cuda.current_device()
        with torch.cuda.device(device_index):
            stream = torch.cuda.current_stream(device_index)
            launch_add_rms_norm(
                dtype,
                input_tensor.data_ptr(),
                residual.data_ptr(),
                weight.data_ptr(),
                rows,
                hidden_size,
                epsilon,
                stream.cuda_stream,
            )

    @torch.library.custom_op(
        "loom_kernels::rms_norm_dynamic_fp8",
        mutates_args={"output", "scales"},
        device_types="cuda",
    )
    def _rms_norm_dynamic_fp8(
        input_tensor: torch.Tensor,
        weight: torch.Tensor,
        output: torch.Tensor,
        scales: torch.Tensor,
        epsilon: float,
    ) -> None:
        dtype, rows, hidden_size = _validate_dynamic_fp8_buffers(
            input_tensor, weight, output, scales, epsilon
        )
        device_index = input_tensor.device.index
        if device_index is None:
            device_index = torch.cuda.current_device()
        with torch.cuda.device(device_index):
            stream = torch.cuda.current_stream(device_index)
            launch_rms_norm_dynamic_fp8(
                dtype,
                input_tensor.data_ptr(),
                weight.data_ptr(),
                output.data_ptr(),
                scales.data_ptr(),
                rows,
                hidden_size,
                epsilon,
                stream.cuda_stream,
            )

    @torch.library.custom_op(
        "loom_kernels::silu_and_mul",
        mutates_args={"output"},
        device_types="cuda",
    )
    def _silu_and_mul(
        input_tensor: torch.Tensor,
        output: torch.Tensor,
    ) -> None:
        dtype, rows, width = _validate_silu_and_mul_buffers(input_tensor, output)
        device_index = input_tensor.device.index
        if device_index is None:
            device_index = torch.cuda.current_device()
        with torch.cuda.device(device_index):
            stream = torch.cuda.current_stream(device_index)
            launch_silu_and_mul(
                dtype,
                input_tensor.data_ptr(),
                output.data_ptr(),
                rows,
                width,
                stream.cuda_stream,
            )

    @torch.library.custom_op(
        "loom_kernels::silu_and_mul_dynamic_fp8",
        mutates_args={"output", "scales"},
        device_types="cuda",
    )
    def _silu_and_mul_dynamic_fp8(
        input_tensor: torch.Tensor,
        output: torch.Tensor,
        scales: torch.Tensor,
        group_size: int,
    ) -> None:
        dtype, rows, width = _validate_silu_and_mul_dynamic_fp8_buffers(
            input_tensor, output, scales, group_size
        )
        device_index = input_tensor.device.index
        if device_index is None:
            device_index = torch.cuda.current_device()
        with torch.cuda.device(device_index):
            stream = torch.cuda.current_stream(device_index)
            launch_silu_and_mul_dynamic_fp8(
                dtype,
                input_tensor.data_ptr(),
                output.data_ptr(),
                scales.data_ptr(),
                rows,
                width,
                group_size,
                stream.cuda_stream,
            )

    _ADAPTER_BACKEND = "python-ctypes"
    _add_rms_norm_mut_unchecked = _add_rms_norm_mut
    _rms_norm_dynamic_fp8_unchecked = _rms_norm_dynamic_fp8
    _silu_and_mul_unchecked = _silu_and_mul
    _silu_and_mul_dynamic_fp8_unchecked = _silu_and_mul_dynamic_fp8
else:
    _add_rms_norm_mut = torch.ops.loom_kernels.add_rms_norm_mut.default
    _add_rms_norm_mut_unchecked = (
        torch.ops.loom_kernels.add_rms_norm_mut_unchecked.default
    )
    _rms_norm_dynamic_fp8 = torch.ops.loom_kernels.rms_norm_dynamic_fp8.default
    _rms_norm_dynamic_fp8_unchecked = (
        torch.ops.loom_kernels.rms_norm_dynamic_fp8_unchecked.default
    )
    _silu_and_mul = torch.ops.loom_kernels.silu_and_mul.default
    _silu_and_mul_unchecked = torch.ops.loom_kernels.silu_and_mul_unchecked.default
    _silu_and_mul_dynamic_fp8 = (
        torch.ops.loom_kernels.silu_and_mul_dynamic_fp8.default
    )
    _silu_and_mul_dynamic_fp8_unchecked = (
        torch.ops.loom_kernels.silu_and_mul_dynamic_fp8_unchecked.default
    )
    _ADAPTER_BACKEND = "cpp-dispatch"


def add_rms_norm_(
    input_tensor: torch.Tensor,
    residual: torch.Tensor,
    weight: torch.Tensor,
    epsilon: float,
) -> tuple[torch.Tensor, torch.Tensor]:
    """Update input/residual in place and return those same tensor objects."""
    _add_rms_norm_mut(input_tensor, residual, weight, float(epsilon))
    return input_tensor, residual


def rms_norm_dynamic_fp8_out(
    input_tensor: torch.Tensor,
    weight: torch.Tensor,
    output: torch.Tensor,
    scales: torch.Tensor,
    epsilon: float,
) -> tuple[torch.Tensor, torch.Tensor]:
    """Write fused RMSNorm and per-token FP8 results into caller-owned buffers."""
    _rms_norm_dynamic_fp8(input_tensor, weight, output, scales, float(epsilon))
    return output, scales


def rms_norm_dynamic_fp8(
    input_tensor: torch.Tensor,
    weight: torch.Tensor,
    epsilon: float,
) -> tuple[torch.Tensor, torch.Tensor]:
    """Return FP8 E4M3FN output and one F32 dequantization scale per row."""
    _, rows, _ = _validate_dynamic_fp8_inputs(input_tensor, weight, epsilon)
    output = torch.empty_like(input_tensor, dtype=torch.float8_e4m3fn)
    scales = torch.empty((rows, 1), device=input_tensor.device, dtype=torch.float32)
    return rms_norm_dynamic_fp8_out(
        input_tensor, weight, output, scales, float(epsilon)
    )


def silu_and_mul_out(
    input_tensor: torch.Tensor,
    output: torch.Tensor,
) -> torch.Tensor:
    """Write split-half `silu(gate) * up` into a caller-owned tensor."""
    _silu_and_mul(input_tensor, output)
    return output


def silu_and_mul(input_tensor: torch.Tensor) -> torch.Tensor:
    """Return split-half `silu(input[..., :d]) * input[..., d:]`."""
    _, _, width = _validate_silu_and_mul_input(input_tensor)
    output = torch.empty(
        (*input_tensor.shape[:-1], width),
        device=input_tensor.device,
        dtype=input_tensor.dtype,
    )
    return silu_and_mul_out(input_tensor, output)


def silu_and_mul_dynamic_fp8_out(
    input_tensor: torch.Tensor,
    output: torch.Tensor,
    scales: torch.Tensor,
    group_size: int = 128,
) -> tuple[torch.Tensor, torch.Tensor]:
    """Write fused SwiGLU and dynamic block-FP8 into caller buffers."""
    _silu_and_mul_dynamic_fp8(input_tensor, output, scales, int(group_size))
    return output, scales


def silu_and_mul_dynamic_fp8(
    input_tensor: torch.Tensor,
    group_size: int = 128,
) -> tuple[torch.Tensor, torch.Tensor]:
    """Return FP8 SwiGLU output and row-major per-block F32 scales."""
    _, rows, width, group_count = _validate_silu_and_mul_dynamic_fp8_input(
        input_tensor, group_size
    )
    output = torch.empty(
        (*input_tensor.shape[:-1], width),
        device=input_tensor.device,
        dtype=torch.float8_e4m3fn,
    )
    scales = torch.empty(
        (rows, group_count), device=input_tensor.device, dtype=torch.float32
    )
    return silu_and_mul_dynamic_fp8_out(
        input_tensor, output, scales, int(group_size)
    )


def mutable_custom_op():
    """Expose the registered op definition for torch.library.opcheck."""
    return _add_rms_norm_mut


def dynamic_fp8_custom_op():
    """Expose the registered FP8 op definition for torch.library.opcheck."""
    return _rms_norm_dynamic_fp8


def dynamic_fp8_unchecked_custom_op():
    """Expose the raw-byte out variant for dispatcher schema validation."""
    return _rms_norm_dynamic_fp8_unchecked


def silu_and_mul_custom_op():
    """Expose the checked SiLU-and-Mul operator for torch.library.opcheck."""
    return _silu_and_mul


def silu_and_mul_dynamic_fp8_custom_op():
    """Expose checked fused activation+FP8 for torch.library.opcheck."""
    return _silu_and_mul_dynamic_fp8


def silu_and_mul_dynamic_fp8_unchecked_custom_op():
    """Expose unchecked fused activation+FP8 for compilation tests."""
    return _silu_and_mul_dynamic_fp8_unchecked


def adapter_backend() -> str:
    """Return the active dispatcher bridge implementation."""
    return _ADAPTER_BACKEND


__all__ = [
    "adapter_backend",
    "add_rms_norm_",
    "dynamic_fp8_custom_op",
    "dynamic_fp8_unchecked_custom_op",
    "mutable_custom_op",
    "rms_norm_dynamic_fp8",
    "rms_norm_dynamic_fp8_out",
    "silu_and_mul",
    "silu_and_mul_custom_op",
    "silu_and_mul_dynamic_fp8",
    "silu_and_mul_dynamic_fp8_custom_op",
    "silu_and_mul_dynamic_fp8_out",
    "silu_and_mul_dynamic_fp8_unchecked_custom_op",
    "silu_and_mul_out",
    "supports_add_rms_norm",
    "supports_rms_norm_dynamic_fp8",
    "supports_silu_and_mul",
    "supports_silu_and_mul_dynamic_fp8",
    "supports_vllm_add_rms_norm",
]
