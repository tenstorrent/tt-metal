# SPDX-FileCopyrightText: © 2024 Tenstorrent Inc.
# SPDX-License-Identifier: Apache-2.0

"""
Integration tests for MiniCPM Qwen model using tt_transformers library.

Tests both text-only and multimodal forward passes with PCC validation.
"""

import torch
import ttnn
from loguru import logger

from tt.ttnn_qwen_minicpm_wrapper import MiniCPMQwenModel
from tt.weight_generator import generate_qwen_weights
from reference.multimodal_qwen import MultimodalQwen2Model
from tt.test_utils import compute_pcc, validate_pcc


def test_minicpm_qwen_text_only(device):
    """
    Test MiniCPM Qwen model text-only forward pass.
    """
    logger.info("🧪 Testing MiniCPM Qwen text-only forward pass")

    # Configuration
    vocab_size = 151700
    hidden_size = 3584
    batch_size = 1
    seq_len = 32

    try:
        # Initialize TTNN model
        model = MiniCPMQwenModel(
            mesh_device=device,
            cross_attention_layers=[8, 16, 24],
            max_seq_len=2048,
            max_batch_size=batch_size,
        )

        # Generate weights
        weights = generate_qwen_weights(
            num_hidden_layers=28,
            cross_attention_layers=[8, 16, 24],
        )

        # Load weights
        model.load_weights(weights)

        # Create input
        input_ids = torch.randint(0, vocab_size, (batch_size, seq_len))

        # TTNN forward pass
        ttnn_output = model.forward(input_ids)
        logger.info(f"✅ TTNN forward pass complete - shape: {ttnn_output.shape}")

        # PyTorch reference
        from reference.multimodal_qwen import MultimodalQwen2Config

        config = MultimodalQwen2Config(
            vocab_size=vocab_size,
            hidden_size=hidden_size,
            intermediate_size=18944,
            num_hidden_layers=28,
            num_attention_heads=28,
            num_key_value_heads=4,
            max_position_embeddings=32768,
            cross_attention_layers=[8, 16, 24],
        )

        pytorch_model = MultimodalQwen2Model(config)
        pytorch_model.load_weights(weights)

        # PyTorch forward pass
        pytorch_output = pytorch_model(input_ids)
        logger.info(f"✅ PyTorch forward pass complete - shape: {pytorch_output.shape}")

        # Compute PCC
        pcc = compute_pcc(pytorch_output, ttnn_output)
        logger.info(f"📊 Text-only PCC: {pcc:.6f}")

        # Validate PCC
        assert validate_pcc(pcc, expected_pcc=0.95), f"PCC {pcc:.6f} < 0.95"

        logger.info("✅ Text-only test passed!")

    except Exception as e:
        logger.error(f"❌ Text-only test failed: {e}")
        raise
    finally:
        if "model" in locals():
            del model


def test_minicpm_qwen_multimodal(device):
    """
    Test MiniCPM Qwen model multimodal forward pass with cross-attention.
    """
    logger.info("🧪 Testing MiniCPM Qwen multimodal forward pass")

    # Configuration
    vocab_size = 151700
    hidden_size = 3584
    batch_size = 1
    seq_len = 32
    vision_seq_len = 64
    audio_seq_len = 64

    try:
        # Initialize TTNN model
        model = MiniCPMQwenModel(
            mesh_device=device,
            cross_attention_layers=[8, 16, 24],
            max_seq_len=2048,
            max_batch_size=batch_size,
        )

        # Generate weights
        weights = generate_qwen_weights(
            num_hidden_layers=28,
            cross_attention_layers=[8, 16, 24],
        )

        # Load weights
        model.load_weights(weights)

        # Create inputs
        input_ids = torch.randint(0, vocab_size, (batch_size, seq_len))
        vision_embeds = torch.randn(batch_size, vision_seq_len, hidden_size)
        audio_embeds = torch.randn(batch_size, audio_seq_len, hidden_size)
        encoder_hidden_states = torch.cat([vision_embeds, audio_embeds], dim=1)

        # TTNN forward pass
        ttnn_output = model.forward(input_ids, encoder_hidden_states)
        logger.info(f"✅ TTNN multimodal forward pass complete - shape: {ttnn_output.shape}")

        # PyTorch reference
        from reference.multimodal_qwen import MultimodalQwen2Config

        config = MultimodalQwen2Config(
            vocab_size=vocab_size,
            hidden_size=hidden_size,
            intermediate_size=18944,
            num_hidden_layers=28,
            num_attention_heads=28,
            num_key_value_heads=4,
            max_position_embeddings=32768,
            cross_attention_layers=[8, 16, 24],
        )

        pytorch_model = MultimodalQwen2Model(config)
        pytorch_model.load_weights(weights)

        # PyTorch forward pass
        pytorch_output = pytorch_model(input_ids, encoder_hidden_states)
        logger.info(f"✅ PyTorch multimodal forward pass complete - shape: {pytorch_output.shape}")

        # Compute PCC
        pcc = compute_pcc(pytorch_output, ttnn_output)
        logger.info(f"📊 Multimodal PCC: {pcc:.6f}")

        # Validate PCC
        assert validate_pcc(pcc, expected_pcc=0.95), f"PCC {pcc:.6f} < 0.95"

        logger.info("✅ Multimodal test passed!")

    except Exception as e:
        logger.error(f"❌ Multimodal test failed: {e}")
        raise
    finally:
        if "model" in locals():
            del model


def test_minicpm_qwen_cross_attention_layers():
    """
    Test that cross-attention layers are correctly configured.
    """
    logger.info("🧪 Testing cross-attention layer configuration")

    # Test that the model is initialized with correct cross-attention layers
    expected_layers = [8, 16, 24]

    # Mock device for testing configuration
    class MockMeshDevice:
        def get_num_devices(self):
            return 1

    mock_device = MockMeshDevice()

    # This test would require the model to be instantiable without actual TTNN device
    # For now, just verify the configuration logic
    assert expected_layers == [8, 16, 24], "Cross-attention layers should be [8, 16, 24]"

    logger.info("✅ Cross-attention layer configuration test passed!")


if __name__ == "__main__":
    # For standalone testing
    logger.info("🔬 Running MiniCPM Qwen integration tests")

    # Initialize device
    device = ttnn.open_mesh_device(
        mesh_shape=(1, 1),
        device_ids=[0],
        l1_small_size=1024,
    )

    try:
        # Run tests
        test_minicpm_qwen_cross_attention_layers()
        test_minicpm_qwen_text_only(device)
        test_minicpm_qwen_multimodal(device)

        logger.info("🎉 All MiniCPM Qwen integration tests passed!")

    except Exception as e:
        logger.error(f"💥 Integration tests failed: {e}")
        raise
    finally:
        ttnn.close_mesh_device(device)
