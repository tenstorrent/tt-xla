# SPDX-FileCopyrightText: (c) 2025 Tenstorrent AI ULC
#
# SPDX-License-Identifier: Apache-2.0
"""
DeBERTa V3 model loader implementation for financial news sentiment analysis.
"""
from typing import Optional

from ....config import (
    ModelConfig,
    ModelInfo,
    ModelGroup,
    ModelTask,
    ModelSource,
    Framework,
    StrEnum,
)
from ....base import ForgeModel


class ModelVariant(StrEnum):
    """Available DeBERTa V3 model variants for sentiment analysis."""

    DEBERTA_V3_FT_FINANCIAL_NEWS_SENTIMENT = "v3_ft_financial_news_sentiment"


class ModelLoader(ForgeModel):
    """DeBERTa V3 model loader implementation for financial news sentiment analysis."""

    _VARIANTS = {
        ModelVariant.DEBERTA_V3_FT_FINANCIAL_NEWS_SENTIMENT: ModelConfig(
            pretrained_model_name="mrm8488/deberta-v3-ft-financial-news-sentiment-analysis",
        ),
    }

    DEFAULT_VARIANT = ModelVariant.DEBERTA_V3_FT_FINANCIAL_NEWS_SENTIMENT

    def __init__(self, variant: Optional[ModelVariant] = None):
        super().__init__(variant)
        self.tokenizer = None

    @classmethod
    def _get_model_info(cls, variant: Optional[ModelVariant] = None) -> ModelInfo:
        if variant is None:
            variant = cls.DEFAULT_VARIANT
        return ModelInfo(
            model="DeBERTa",
            variant=variant,
            group=ModelGroup.VULCAN,
            task=ModelTask.NLP_TEXT_CLS,
            source=ModelSource.HUGGING_FACE,
            framework=Framework.TORCH,
        )

    def load_model(self, *, dtype_override=None, **kwargs):
        from transformers import AutoModelForSequenceClassification, AutoTokenizer

        pretrained_model_name = self._variant_config.pretrained_model_name

        self.tokenizer = AutoTokenizer.from_pretrained(pretrained_model_name)

        model_kwargs = {}
        if dtype_override is not None:
            model_kwargs["torch_dtype"] = dtype_override
        model_kwargs |= kwargs

        model = AutoModelForSequenceClassification.from_pretrained(
            pretrained_model_name, **model_kwargs
        )
        model.eval()
        return model

    def load_inputs(self, dtype_override=None):
        if self.tokenizer is None:
            from transformers import AutoTokenizer

            self.tokenizer = AutoTokenizer.from_pretrained(
                self._variant_config.pretrained_model_name
            )

        text = "Tesla stock surged 10% after strong quarterly earnings report."

        inputs = self.tokenizer(
            text,
            max_length=128,
            padding="max_length",
            truncation=True,
            return_tensors="pt",
        )

        return inputs

    def decode_output(self, co_out):
        logits = co_out[0]
        predicted_class_id = logits.argmax(-1).item()
        labels = ["negative", "neutral", "positive"]
        print(f"Predicted sentiment: {labels[predicted_class_id]}")
