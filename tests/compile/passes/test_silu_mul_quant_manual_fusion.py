# SPDX-License-Identifier: Apache-2.0
# SPDX-FileCopyrightText: Copyright contributors to the vLLM project
"""Tests for manual fusion via maybe_fused_act_quant.

Tests all fusion paths in _FUSED_ACT_QUANT:
- kFp8StaticTensorSym: all platforms
- kFp8Dynamic128Sym: CUDA only
- kNvfp4Dynamic: CUDA SM100+ only
"""

import pytest
import torch

import vllm.envs as envs
from tests.utils import TestFP8Layer
from vllm.config import (
    CompilationConfig,
    VllmConfig,
    set_current_vllm_config,
)
from vllm.model_executor.kernels.linear import (
    CutlassFp8BlockScaledMMKernel,
    CutlassFP8ScaledMMLinearKernel,
    FlashInferFP8ScaledMMLinearKernel,
    FP8ScaledMMLinearKernel,
    PerTensorTorchFP8ScaledMMLinearKernel,
    ROCmFP8ScaledMMLinearKernel,
)
from vllm.model_executor.kernels.linear.scaled_mm.ScaledMMLinearKernel import (
    FP8ScaledMMLinearLayerConfig,
)
from vllm.model_executor.layers.activation import SiluAndMul
from vllm.model_executor.layers.fusion.fused_act_quant import (
    _FUSED_ACT_QUANT,
    maybe_fused_act_quant,
)
from vllm.model_executor.layers.fusion.quant_activation import (
    QuantizedActivation,
    expose_input_quant_key,
    get_input_quant_key,
)
from vllm.model_executor.layers.quantization.utils.quant_utils import (
    kFp8Dynamic128Sym,
    kFp8Static128BlockSym,
    kFp8StaticTensorSym,
    kNvfp4Dynamic,
)
from vllm.platforms import current_platform


# Mock linear layer for testing fusion paths that don't have real kernel support
class MockLinearForFusion(torch.nn.Module):
    """Mock linear layer that exposes an input key for fusion testing."""

    def __init__(
        self,
        quant_key,
        input_scale=None,
        input_global_scale=None,
        input_global_scale_inv=None,
    ):
        super().__init__()
        self._input_quant_key = quant_key
        if input_scale is not None:
            self.input_scale = input_scale
        if input_global_scale is not None:
            self.input_global_scale = input_global_scale
        if input_global_scale_inv is not None:
            self.input_global_scale_inv = input_global_scale_inv


ROCM_KERNELS = [ROCmFP8ScaledMMLinearKernel, PerTensorTorchFP8ScaledMMLinearKernel]
CUDA_KERNELS = [
    FlashInferFP8ScaledMMLinearKernel,
    CutlassFP8ScaledMMLinearKernel,
    PerTensorTorchFP8ScaledMMLinearKernel,
]
TEST_KERNELS = ROCM_KERNELS if current_platform.is_rocm() else CUDA_KERNELS


@pytest.mark.parametrize("num_tokens", [32, 64])
@pytest.mark.parametrize("hidden_size", [128, 256])
@pytest.mark.parametrize("dtype", [torch.bfloat16, torch.float16])
@pytest.mark.parametrize("force_kernel", TEST_KERNELS)
@pytest.mark.skipif(
    envs.VLLM_TARGET_DEVICE not in ["cuda", "rocm"], reason="Only test on CUDA and ROCm"
)
def test_manual_fusion_fp8_static_with_linear(
    num_tokens: int,
    hidden_size: int,
    dtype: torch.dtype,
    force_kernel: type[FP8ScaledMMLinearKernel],
):
    """Test manual fusion with real FP8 linear layer (kFp8StaticTensorSym).

    This is an end-to-end test that verifies the full flow:
    unfused (silu_and_mul -> in-kernel quant) vs fused (silu_and_mul_quant).
    """
    torch.set_default_device("cuda")
    torch.set_default_dtype(dtype)

    x = torch.rand(num_tokens, hidden_size * 2)

    config = VllmConfig(
        compilation_config=CompilationConfig(custom_ops=["none"]),
    )

    with set_current_vllm_config(config):
        silu_and_mul = SiluAndMul()
        fp8_linear = TestFP8Layer(
            weight_shape=(hidden_size, hidden_size),
            activation_quant_key=kFp8StaticTensorSym,
            weight_quant_key=kFp8StaticTensorSym,
            force_kernel=force_kernel,
            input_dtype=dtype,
        )

        # Run without fusion: silu_and_mul returns plain tensor
        y_unfused = maybe_fused_act_quant(silu_and_mul, x, fp8_linear)
        assert isinstance(y_unfused, torch.Tensor)
        result_unfused = fp8_linear(y_unfused)

        # Enable fusion
        expose_input_quant_key(fp8_linear, fp8_linear.kernel)

        if get_input_quant_key(fp8_linear) is None:
            pytest.skip(
                f"Kernel {force_kernel.__name__} doesn't support input_quant_key"
            )

        # Run with fusion: silu_and_mul returns QuantizedActivation
        y_fused = maybe_fused_act_quant(silu_and_mul, x, fp8_linear)
        assert isinstance(y_fused, QuantizedActivation)
        assert y_fused.quant_key == kFp8StaticTensorSym
        assert y_fused.data.dtype == current_platform.fp8_dtype()
        assert y_fused.data.shape == (num_tokens, hidden_size)
        assert y_fused.orig_dtype == dtype
        assert y_fused.orig_shape == (num_tokens, hidden_size)

        result_fused = fp8_linear(y_fused)

        torch.testing.assert_close(
            result_fused.to(dtype=dtype),
            result_unfused.to(dtype=dtype),
            atol=5e-2,
            rtol=5e-2,
        )


@pytest.mark.parametrize("dtype", [torch.bfloat16, torch.float16])
@pytest.mark.skipif(
    not current_platform.is_cuda_alike(), reason="Dynamic block quant CUDA only"
)
@pytest.mark.skipif(
    envs.VLLM_TARGET_DEVICE not in ["cuda", "rocm"], reason="Only test on CUDA and ROCm"
)
def test_manual_fusion_fp8_dynamic_128(dtype: torch.dtype):
    """Test kFp8Dynamic128Sym fusion path (group_size=128).

    Compares fused (silu_and_mul_per_block_quant) vs unfused (silu_and_mul)
    by dequantizing the fused result and comparing with unfused.
    """
    if (SiluAndMul, kFp8Dynamic128Sym) not in _FUSED_ACT_QUANT:
        pytest.skip("kFp8Dynamic128Sym fusion not available")

    torch.set_default_device("cuda")
    torch.set_default_dtype(dtype)

    # hidden_size must be divisible by group_size (128)
    num_tokens, hidden_size = 32, 256
    group_size = 128
    x = torch.rand(num_tokens, hidden_size * 2)

    config = VllmConfig(
        compilation_config=CompilationConfig(custom_ops=["none"]),
    )

    with set_current_vllm_config(config):
        silu_and_mul = SiluAndMul()

        # Unfused path: just apply silu_and_mul
        mock_linear_no_key = torch.nn.Linear(hidden_size, hidden_size)
        result_unfused = maybe_fused_act_quant(silu_and_mul, x, mock_linear_no_key)
        assert isinstance(result_unfused, torch.Tensor)

        # Fused path: apply silu_and_mul + per-block quantization
        mock_linear_with_key = MockLinearForFusion(kFp8Dynamic128Sym)
        result_fused = maybe_fused_act_quant(silu_and_mul, x, mock_linear_with_key)

        # Verify fused result structure
        assert isinstance(result_fused, QuantizedActivation)
        assert result_fused.quant_key == kFp8Dynamic128Sym
        assert result_fused.data.dtype == current_platform.fp8_dtype()
        assert result_fused.data.shape == (num_tokens, hidden_size)
        assert result_fused.orig_dtype == dtype

        # Check scale shape
        expected_num_groups = hidden_size // group_size
        assert result_fused.scale.shape == (num_tokens, expected_num_groups)

        # Dequantize fused result and compare with unfused
        # Per-block dequant: data * scale (broadcast scale across group)
        dequant_data = result_fused.data.to(dtype).view(
            num_tokens, expected_num_groups, group_size
        )
        scales_expanded = result_fused.scale.unsqueeze(
            -1
        )  # (num_tokens, num_groups, 1)
        dequant_result = (
            (dequant_data * scales_expanded).view(num_tokens, hidden_size).to(dtype)
        )

        torch.testing.assert_close(
            dequant_result,
            result_unfused,
            atol=5e-2,
            rtol=5e-2,
        )


@pytest.mark.parametrize("num_tokens", [1, 33, 256])
@pytest.mark.skipif(
    not current_platform.is_cuda()
    or not CutlassFp8BlockScaledMMKernel.is_supported()[0],
    reason="CUTLASS block FP8 not supported",
)
def test_manual_fusion_fp8_dynamic_128_cutlass(num_tokens: int):
    """The fused producer matches CUTLASS block FP8's own input quant, and the
    kernel consumes a pre-quantized input exactly like its own."""
    torch.set_default_device("cuda")
    torch.set_default_dtype(torch.bfloat16)
    g = torch.Generator(device="cuda").manual_seed(0)
    n, k = 512, 1024
    config = FP8ScaledMMLinearLayerConfig(
        activation_quant_key=kFp8Dynamic128Sym,
        weight_quant_key=kFp8Static128BlockSym,
        weight_shape=(n, k),
        input_dtype=torch.bfloat16,
        out_dtype=torch.bfloat16,
    )
    with set_current_vllm_config(
        VllmConfig(compilation_config=CompilationConfig(custom_ops=["none"]))
    ):
        kernel = CutlassFp8BlockScaledMMKernel(config)
        layer = torch.nn.Module()
        weight = torch.randn(n, k, generator=g) / k**0.5
        layer.weight = torch.nn.Parameter(
            weight.to(current_platform.fp8_dtype()), requires_grad=False
        )
        layer.weight_scale_inv = torch.nn.Parameter(
            torch.rand(n // 128, k // 128, generator=g, dtype=torch.float32) + 0.5,
            requires_grad=False,
        )
        layer.input_scale = None
        kernel.process_weights_after_loading(layer)
        expose_input_quant_key(layer, kernel)

        silu_and_mul = SiluAndMul()
        x = torch.randn(num_tokens, 2 * k, generator=g)
        fused = maybe_fused_act_quant(silu_and_mul, x, layer)
        assert isinstance(fused, QuantizedActivation)
        y = silu_and_mul(x)
        q_ref, s_ref = kernel.quant_fp8(y, None, None)

        # Producer vs the kernel's own quant. Codes can move by one FP8 step:
        # the fused kernel keeps silu*mul in fp32, the chain rounds it to bf16.
        codes = []
        for q in (fused.data, q_ref):
            b = q.view(torch.uint8).to(torch.int32)
            codes.append(torch.where(b >= 128, 128 - b, b))  # +0 == -0
        code_dist = (codes[0] - codes[1]).abs()
        assert code_dist.max().item() <= 1
        assert (code_dist > 0).float().mean().item() < 0.05
        scale = fused.scale.view(-1, fused.scale.shape[-1])
        if num_tokens > 1:  # strides of a size-1 dim are arbitrary
            assert scale.stride() == s_ref.stride()
        torch.testing.assert_close(scale, s_ref, rtol=1e-2, atol=0)

        # Consumer: a pre-quantized input gives exactly the in-kernel quant result.
        qa_ref = QuantizedActivation(
            data=q_ref,
            scale=s_ref,
            orig_dtype=torch.bfloat16,
            orig_shape=y.shape,
            quant_key=kFp8Dynamic128Sym,
        )
        assert torch.equal(
            kernel.apply_weights(layer, qa_ref), kernel.apply_weights(layer, y)
        )


@pytest.mark.parametrize("dtype", [torch.bfloat16, torch.float16])
# Cover M < 128 (padded swizzled SF tiles) and hidden_size that makes the
# kernel launch grid.y > 1 (num_packed_cols = hidden_size / 16 > 512).
@pytest.mark.parametrize("num_tokens", [1, 127, 128])
@pytest.mark.parametrize("hidden_size", [256, 14336])
@pytest.mark.skipif(not current_platform.is_cuda(), reason="NVFP4 CUDA only")
@pytest.mark.skipif(
    not current_platform.has_device_capability(100), reason="NVFP4 requires SM100+"
)
@pytest.mark.skipif(
    envs.VLLM_TARGET_DEVICE not in ["cuda", "rocm"], reason="Only test on CUDA and ROCm"
)
def test_manual_fusion_nvfp4_dynamic(
    dtype: torch.dtype, num_tokens: int, hidden_size: int
):
    """Test kNvfp4Dynamic fusion path.

    Compares fused (silu_and_mul_nvfp4_quant) vs unfused (silu_and_mul)
    by dequantizing the fused result and comparing with unfused.
    """
    if (SiluAndMul, kNvfp4Dynamic) not in _FUSED_ACT_QUANT:
        pytest.skip("kNvfp4Dynamic fusion not available")

    from tests.kernels.quantization.nvfp4_utils import dequantize_nvfp4_to_dtype

    torch.set_default_device("cuda")
    torch.set_default_dtype(dtype)

    # NVFP4 requires hidden_size divisible by 16 (block size) and by 2 (packing).
    x = torch.rand(num_tokens, hidden_size * 2)
    # Non-1.0 global scale so the test is sensitive to the scale direction:
    # the fused producer must quantize with input_global_scale_inv (the GEMM's
    # alpha divides by input_global_scale), matching the unfused path.
    input_global_scale = torch.tensor([0.5], dtype=torch.float32, device="cuda")
    input_global_scale_inv = 1.0 / input_global_scale

    config = VllmConfig(
        compilation_config=CompilationConfig(custom_ops=["none"]),
    )

    with set_current_vllm_config(config):
        silu_and_mul = SiluAndMul()

        # Unfused path: just apply silu_and_mul
        mock_linear_no_key = torch.nn.Linear(hidden_size, hidden_size)
        result_unfused = maybe_fused_act_quant(silu_and_mul, x, mock_linear_no_key)
        assert isinstance(result_unfused, torch.Tensor)

        # Fused path: apply silu_and_mul + NVFP4 quantization
        mock_linear_with_key = MockLinearForFusion(
            kNvfp4Dynamic,
            input_global_scale=input_global_scale,
            input_global_scale_inv=input_global_scale_inv,
        )
        result_fused = maybe_fused_act_quant(silu_and_mul, x, mock_linear_with_key)

        # Verify fused result structure
        assert isinstance(result_fused, QuantizedActivation)
        assert result_fused.quant_key == kNvfp4Dynamic
        # NVFP4 packs 2 values into 1 byte
        assert result_fused.data.dtype == torch.uint8
        assert result_fused.data.shape == (num_tokens, hidden_size // 2)
        assert result_fused.orig_dtype == dtype
        assert result_fused.orig_shape == (num_tokens, hidden_size)

        # The scale tensor must use the padded 128x4-tile swizzled layout,
        # same as scaled_fp4_quant's allocator; the kernel writes a full
        # 128-row tile even when M is smaller.
        from vllm.utils.math_utils import round_up

        assert result_fused.scale.dtype == current_platform.fp8_dtype()
        assert result_fused.scale.shape == (
            round_up(num_tokens, 128),
            round_up(hidden_size // 16, 4),
        )

        # Dequantize fused result and compare with unfused. The block scales
        # must have been folded with input_global_scale_inv, so dequantize
        # with the same inverse scale to recover the activation.
        dequant_result = dequantize_nvfp4_to_dtype(
            tensor_fp4=result_fused.data,
            tensor_sf=result_fused.scale,
            global_scale=input_global_scale_inv,
            dtype=dtype,
            device="cuda",
            block_size=16,
            is_sf_128x4_layout=True,
        )

        torch.testing.assert_close(
            dequant_result,
            result_unfused,
            atol=3e-1,
            rtol=3e-1,
        )


@pytest.mark.parametrize("dtype", [torch.bfloat16, torch.float16])
@pytest.mark.skipif(
    envs.VLLM_TARGET_DEVICE not in ["cuda", "rocm"], reason="Only test on CUDA and ROCm"
)
def test_manual_fusion_fallback_no_key(dtype: torch.dtype):
    """Test that maybe_fused_act_quant falls back without an input key."""
    torch.set_default_device("cuda")
    torch.set_default_dtype(dtype)

    x = torch.rand(32, 256)

    config = VllmConfig(
        compilation_config=CompilationConfig(custom_ops=["none"]),
    )

    with set_current_vllm_config(config):
        silu_and_mul = SiluAndMul()
        # Linear without an input quantization key
        mock_linear = torch.nn.Linear(128, 128)

        result = maybe_fused_act_quant(silu_and_mul, x, mock_linear)

        # Should fall back to plain silu_and_mul
        assert isinstance(result, torch.Tensor)
        assert result.shape == (32, 128)
        assert result.dtype == dtype


@pytest.mark.parametrize("dtype", [torch.bfloat16, torch.float16])
@pytest.mark.skipif(
    envs.VLLM_TARGET_DEVICE not in ["cuda", "rocm"], reason="Only test on CUDA and ROCm"
)
def test_manual_fusion_fallback_unsupported_key(dtype: torch.dtype):
    """Test that maybe_fused_act_quant falls back for unsupported quant keys."""
    from vllm.model_executor.layers.quantization.utils.quant_utils import (
        GroupShape,
        QuantKey,
        ScaleDesc,
    )

    torch.set_default_device("cuda")
    torch.set_default_dtype(dtype)

    x = torch.rand(32, 256)

    config = VllmConfig(
        compilation_config=CompilationConfig(custom_ops=["none"]),
    )

    with set_current_vllm_config(config):
        # Create an unsupported quant key
        unsupported_key = QuantKey(
            dtype=torch.int8,
            scale=ScaleDesc(
                dtype=torch.float32, static=False, group_shape=GroupShape(1, 1)
            ),
        )

        silu_and_mul = SiluAndMul()
        mock_linear = MockLinearForFusion(unsupported_key)

        result = maybe_fused_act_quant(silu_and_mul, x, mock_linear)

        # Should fall back to plain silu_and_mul since key not in _FUSED_ACT_QUANT
        assert isinstance(result, torch.Tensor)
        assert result.shape == (32, 128)
        assert result.dtype == dtype
