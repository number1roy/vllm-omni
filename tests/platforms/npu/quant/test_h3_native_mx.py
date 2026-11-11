# SPDX-License-Identifier: Apache-2.0
# SPDX-FileCopyrightText: Copyright contributors to the vLLM-Omni project
"""Real A5 MX kernels, padding, output chunking, and VAE dtype boundaries."""

import pytest
import torch

from tests.helpers.mark import hardware_marks
from vllm_omni.diffusion.models.minimax_h3.native_mx import native_mx_linear, quantize_mx_weight
from vllm_omni.diffusion.models.minimax_h3.offline_quantization import reconstruct_mx_weight

pytestmark = [pytest.mark.advanced_model, pytest.mark.diffusion, *hardware_marks(res={"npu": "A5"}, num_cards=1)]
torch_npu = pytest.importorskip("torch_npu")


@pytest.mark.parametrize("bits", [4, 8])
@pytest.mark.parametrize("shape", [(2, 3, 24), (7, 32), (3, 64)])
@torch.inference_mode()
def test_native_mx_matches_independently_decoded_operands(bits, shape):
    torch.manual_seed(43)
    device = torch.device("npu:0")
    x = torch.randn(shape, dtype=torch.float32, device=device)
    weight = torch.randn(128, shape[-1], dtype=torch.bfloat16)
    bias = torch.randn(128, dtype=torch.float32, device=device)
    q, scale = quantize_mx_weight(weight, bits, device)
    actual = native_mx_linear(x, q, scale, bits, bias)
    padded_k = q.shape[1] * (2 if bits == 4 else 1)
    xp = torch.nn.functional.pad(x.reshape(-1, shape[-1]).bfloat16(), (0, padded_k - shape[-1]))
    dtype = torch_npu.float4_e2m1fn_x2 if bits == 4 else torch_npu.float8_e4m3fn
    xq, xs = torch_npu.npu_dynamic_mx_quant(xp, dst_type=dtype)
    x_reference = reconstruct_mx_weight(xq.cpu(), xs.cpu().reshape(xp.shape[0], -1))
    w_bytes = q.cpu()
    w_native = w_bytes if bits == 4 else w_bytes.view(torch.float8_e4m3fn)
    w_reference = reconstruct_mx_weight(w_native, scale.cpu().flatten(1))
    expected = (x_reference @ w_reference.T).bfloat16().float() + bias.cpu()
    torch.npu.synchronize()
    assert actual.dtype == x.dtype
    assert tuple(actual.shape) == (*shape[:-1], 128)
    assert torch.isfinite(actual).all()
    torch.testing.assert_close(actual.cpu().reshape_as(expected), expected, rtol=0.025, atol=0.125)


@pytest.mark.parametrize("bits", [4, 8])
@torch.inference_mode()
def test_native_mx_wide_adaln_stays_low_bit(bits):
    device = torch.device("npu:0")
    weight = torch.ones(96768, 64, dtype=torch.bfloat16)
    q, scale = quantize_mx_weight(weight, bits, device)
    actual = native_mx_linear(torch.ones(2, 64, dtype=torch.bfloat16, device=device), q, scale, bits, None)
    torch.npu.synchronize()
    torch.testing.assert_close(actual.cpu(), torch.full((2, 96768), 64, dtype=torch.bfloat16))
