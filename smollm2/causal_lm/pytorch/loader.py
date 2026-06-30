# SPDX-FileCopyrightText: (c) 2025 Tenstorrent AI ULC
#
# SPDX-License-Identifier: Apache-2.0
"""SmolLM2 model loader implementation for causal language modeling."""

from typing import Optional

import torch
from transformers import AutoModelForCausalLM, AutoTokenizer

from ....config import (
    Framework,
    LLMModelConfig,
    ModelGroup,
    ModelInfo,
    ModelSource,
    ModelTask,
    StrEnum,
)
from ....base import ForgeModel
from ....tools.utils import cast_input_to_type, pad_inputs


class ModelVariant(StrEnum):
    """Available SmolLM2 model variants for causal LM."""

    SMOLLM2_360M = "360M"


class ModelLoader(ForgeModel):
    """SmolLM2 model loader for causal language modeling tasks."""

    _VARIANTS = {
        ModelVariant.SMOLLM2_360M: LLMModelConfig(
            pretrained_model_name="HuggingFaceTB/SmolLM2-360M",
            max_length=128,
        ),
    }

    DEFAULT_VARIANT = ModelVariant.SMOLLM2_360M

    sample_text = "Hey how are you doing today?"

    def __init__(self, variant: Optional[ModelVariant] = None):
        super().__init__(variant)
        self.tokenizer = None
        self.seq_len = None

    @classmethod
    def _get_model_info(cls, variant: Optional[ModelVariant] = None) -> ModelInfo:
        if variant is None:
            variant = cls.DEFAULT_VARIANT
        return ModelInfo(
            model="SmolLM2",
            variant=variant,
            group=ModelGroup.GENERALITY,
            task=ModelTask.NLP_CAUSAL_LM,
            source=ModelSource.HUGGING_FACE,
            framework=Framework.TORCH,
        )

    def _load_tokenizer(self, dtype_override=None):
        pretrained_model_name = self._variant_config.pretrained_model_name
        self.tokenizer = AutoTokenizer.from_pretrained(pretrained_model_name)
        if self.tokenizer.pad_token is None:
            self.tokenizer.pad_token = self.tokenizer.eos_token
        return self.tokenizer

    def load_model(self, *, dtype_override=None, **kwargs):
        """Load and return the SmolLM2 model for the configured variant.

        Args:
            dtype_override: Optional torch.dtype to cast the model weights.

        Returns:
            torch.nn.Module: The SmolLM2 model instance.
        """
        pretrained_model_name = self._variant_config.pretrained_model_name

        if self.tokenizer is None:
            self._load_tokenizer()

        model_kwargs = {}
        if dtype_override is not None:
            model_kwargs["torch_dtype"] = dtype_override

        model = AutoModelForCausalLM.from_pretrained(
            pretrained_model_name, **model_kwargs
        )
        model.eval()
        return model

    def load_inputs(self, dtype_override=None, batch_size=1):
        """Load sample inputs for the SmolLM2 model.

        Args:
            dtype_override: Optional torch.dtype for casting inputs.
            batch_size: Batch size for inputs.

        Returns:
            dict: Tokenized inputs with input_ids and attention_mask.
        """
        if self.tokenizer is None:
            self._load_tokenizer()

        inputs = self.tokenizer(self.sample_text, return_tensors="pt")

        for key in inputs:
            inputs[key] = inputs[key].repeat_interleave(batch_size, dim=0)

        if dtype_override is not None:
            for key in inputs:
                inputs[key] = cast_input_to_type(inputs[key], dtype_override)

        target_len = self._variant_config.max_length
        padded_input_ids, seq_len = pad_inputs(inputs["input_ids"], target_len)
        padded_attention_mask, _ = pad_inputs(inputs["attention_mask"], target_len)
        self.seq_len = seq_len

        inputs["input_ids"] = padded_input_ids
        inputs["attention_mask"] = padded_attention_mask
        return inputs
