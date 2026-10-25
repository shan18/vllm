# SPDX-License-Identifier: Apache-2.0
# SPDX-FileCopyrightText: Copyright contributors to the vLLM project
# Copyright (c) 2026, NVIDIA CORPORATION. All rights reserved.
"""Configuration for the recurrent Koi hybrid architecture."""

from huggingface_hub.dataclasses import strict
from transformers.configuration_utils import PreTrainedConfig


@strict
class KoiConfig(PreTrainedConfig):
    model_type = "koi"

    vocab_size: int = 131072
    hidden_size: int = 3072
    num_hidden_layers: int = 52
    layer_types: list[str] | None = None
    n_input_layers: int = 14
    n_recurrent_layers: int = 24
    n_output_layers: int = 14
    n_recurrent_loops: int = 4
    recurrent_kv_cache_mode: str = "per_loop"
    num_attention_heads: int = 24
    num_key_value_heads: int = 8
    head_dim: int = 128
    intermediate_size: int = 12288
    hidden_act: str = "relu2"
    linear_num_value_heads: int = 96
    linear_value_head_dim: int = 32
    linear_num_key_heads: int = 8
    linear_key_head_dim: int = 64
    linear_conv_kernel_dim: int = 4
    linear_num_householder: int = 3
    loop_conditioning_hidden_size: int = 256
    loop_conditioning_max_loops: int = 4
    loop_adapter_rank: int = 256
    loop_input_mixing: bool = True
    rms_norm_eps: float = 1e-5
    max_position_embeddings: int = 262144
    tie_word_embeddings: bool = False
    bos_token_id: int | None = 1
    eos_token_id: int | list[int] | None = 11
    pad_token_id: int | None = 11

    def __post_init__(self, **kwargs):
        if self.layer_types is None:
            pattern = "M-M-M*-M-M-M*-M-M-M*-M-M-M*-M-M-M*-M-M-M-M*-M-M-M-M-"
            kinds = {"M": "linear_attention", "*": "full_attention", "-": "mlp"}
            self.layer_types = [kinds[kind] for kind in pattern]
        super().__post_init__(**kwargs)

    def validate_layer_type(self):
        if self.layer_types is None or len(self.layer_types) != self.num_hidden_layers:
            raise ValueError("layer_types must have num_hidden_layers entries")
        if set(self.layer_types) - {"linear_attention", "full_attention", "mlp"}:
            raise ValueError(
                "Koi layers must be linear_attention, full_attention, or mlp"
            )

    def validate_architecture(self):
        legacy = {
            "hybrid_layer_pattern",
            "num_input_layers",
            "num_recurrent_layers",
            "num_output_layers",
            "num_loops",
            "max_loops",
            "kv_cache_loops",
            "loop_cond_dim",
            "loop_cond_max_loops",
            "loop_cond_lowrank_dim",
            "loop_cond_input_mix",
        }
        if legacy.intersection(vars(self)):
            raise ValueError(
                "Convert legacy Koi configs with translate_hf_koi_config.py"
            )
        partitions = (
            self.n_input_layers,
            self.n_recurrent_layers,
            self.n_output_layers,
        )
        if min(partitions) < 0 or sum(partitions) != self.num_hidden_layers:
            raise ValueError("Koi layer partitions must sum to num_hidden_layers")
        if self.n_recurrent_layers < 1 or self.n_recurrent_loops < 1:
            raise ValueError(
                "n_recurrent_layers and n_recurrent_loops must be positive"
            )
        if self.recurrent_kv_cache_mode not in ("per_loop", "last_loop"):
            raise ValueError("recurrent_kv_cache_mode must be per_loop or last_loop")
        dimensions = (
            self.hidden_size,
            self.intermediate_size,
            self.num_attention_heads,
            self.num_key_value_heads,
            self.head_dim,
            self.linear_num_value_heads,
            self.linear_value_head_dim,
            self.linear_num_key_heads,
            self.linear_key_head_dim,
            self.linear_num_householder,
            self.loop_conditioning_hidden_size,
            self.loop_conditioning_max_loops,
        )
        if min(dimensions) <= 0:
            raise ValueError("Koi dimensions must be positive")
        if self.num_attention_heads % self.num_key_value_heads:
            raise ValueError(
                "num_attention_heads must be divisible by num_key_value_heads"
            )
        if self.linear_num_value_heads % self.linear_num_key_heads:
            raise ValueError(
                "linear_num_value_heads must be divisible by linear_num_key_heads"
            )
        if self.linear_conv_kernel_dim not in (2, 3, 4):
            raise ValueError("linear_conv_kernel_dim must be 2, 3, or 4")
        if self.loop_conditioning_hidden_size % 2 or self.loop_adapter_rank < 0:
            raise ValueError(
                "Loop conditioning size must be even and adapter rank nonnegative"
            )
        if self.hidden_act != "relu2" or self.rms_norm_eps <= 0:
            raise ValueError("Koi requires relu2 and positive rms_norm_eps")
