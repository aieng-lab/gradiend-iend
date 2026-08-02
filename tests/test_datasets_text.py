"""
Tests for TextGradientTrainingDataset (text-specific).

Tests text-specific dataset functionality including padding, caching,
and data loading variations (add_identity_for_other_classes, max_size).
"""

import os
import pandas as pd
from unittest.mock import MagicMock

import pytest
import torch

from gradiend.trainer.text.common.dataset import TextGradientTrainingDataset
from gradiend.trainer.text.prediction.dataset import TextActivationTrainingDataset, TextTrainingDataset
from gradiend.trainer.text.prediction.trainer import TextPredictionTrainer
from gradiend.trainer.core.arguments import TrainingArguments
from gradiend.trainer.core.dataset import SignalTrainingDatasetBase
from gradiend.trainer.core.signals import ActivationSignalExtractor, Signal, SignalBatch, SignalScope
from tests.testing_mocks import MockTokenizer, SimpleMockModel


class TestTextGradientTrainingDataset:
    """Test TextGradientTrainingDataset (text-specific wrapper)."""
    
    def test_signal_dataset_identity_diff_reuses_factual_signal(self):
        class OneIdentityRow:
            batch_size = 1

            def __len__(self):
                return 1

            def __getitem__(self, _idx):
                return {
                    "factual": torch.tensor([1.0, 2.0]),
                    "alternative": torch.tensor([99.0, 100.0]),
                    "is_identity_transition": True,
                    "label": 0,
                }

        class RecordingExtractor:
            signal = Signal.gradient()

            def __init__(self):
                self.calls = []

            def __call__(
                self,
                factual_inputs=None,
                alternative_inputs=None,
                *,
                requires_factual=True,
                requires_alternative=True,
            ):
                self.calls.append(
                    {
                        "factual_inputs": factual_inputs,
                        "alternative_inputs": alternative_inputs,
                        "requires_factual": requires_factual,
                        "requires_alternative": requires_alternative,
                    }
                )
                factual = factual_inputs * 2 if requires_factual else None
                alternative = alternative_inputs * 3 if requires_alternative else None
                return SignalBatch.from_factual_alternative(
                    factual,
                    alternative,
                    signal_id="gradient",
                )

        extractor = RecordingExtractor()
        dataset = SignalTrainingDatasetBase(
            OneIdentityRow(),
            extractor,
            source="factual",
            target="diff",
            signal=Signal.gradient(),
        )

        row = dataset[0]

        assert len(extractor.calls) == 1
        assert extractor.calls[0]["requires_factual"] is True
        assert extractor.calls[0]["requires_alternative"] is False
        assert row["source"].tolist() == [2.0, 4.0]
        assert row["target"].abs().sum().item() == 0.0

    def test_text_dataset_creation(self):
        """Test that TextGradientTrainingDataset can be created."""
        tokenizer = MockTokenizer()
        training_data = MagicMock()
        training_data.__len__ = MagicMock(return_value=10)
        training_data.batch_size = 1
        training_data.__getitem__ = MagicMock(return_value={
            "factual": {"input_ids": torch.tensor([1, 2, 3])},
            "alternative": {"input_ids": torch.tensor([4, 5, 6])},
            "input_text": "test",
            "label": "positive"
        })
        
        gradient_creator = MagicMock(return_value=torch.randn(100))
        
        dataset = TextGradientTrainingDataset(
            training_data=training_data,
            tokenizer=tokenizer,
            gradient_creator=gradient_creator,
            source="factual",
            target="diff"
        )
        
        assert dataset.tokenizer == tokenizer
        assert dataset.gradient_creator == gradient_creator
        assert dataset.source == "factual"
        assert dataset.target == "diff"

    def test_text_dataset_accepts_gradient_signal(self):
        tokenizer = MockTokenizer()
        training_data = MagicMock()
        training_data.__len__ = MagicMock(return_value=1)
        training_data.batch_size = 1
        training_data.__getitem__ = MagicMock(return_value={
            "factual": {"input_ids": torch.tensor([1, 2, 3])},
            "alternative": {"input_ids": torch.tensor([4, 5, 6])},
            "input_text": "test",
            "label": "positive",
        })
        gradient_creator = MagicMock(return_value=torch.randn(100))

        dataset = TextGradientTrainingDataset(
            training_data=training_data,
            tokenizer=tokenizer,
            gradient_creator=gradient_creator,
            signal=Signal.gradient(),
        )

        assert dataset.signal == Signal.gradient()
        assert dataset.signals.ids == ("gradient",)

    def test_text_dataset_rejects_unsupported_activation_signal(self):
        tokenizer = MockTokenizer()
        training_data = MagicMock()
        training_data.__len__ = MagicMock(return_value=1)
        training_data.batch_size = 1
        gradient_creator = MagicMock(return_value=torch.randn(100))

        with pytest.raises(NotImplementedError, match="Signal.gradient"):
            TextGradientTrainingDataset(
                training_data=training_data,
                tokenizer=tokenizer,
                gradient_creator=gradient_creator,
                signal=Signal.activation(),
            )
    
    def test_text_dataset_padding_uses_tokenizer_pad_token_id(self):
        """Test that text dataset uses tokenizer.pad_token_id for padding."""
        tokenizer = MockTokenizer()
        tokenizer.pad_token_id = 999
        
        training_data = MagicMock()
        training_data.__len__ = MagicMock(return_value=1)
        training_data.__getitem__ = MagicMock(return_value={
            "factual": {"input_ids": torch.tensor([1, 2, 3])},
            "alternative": {"input_ids": torch.tensor([4, 5])},
            "input_text": "test",
            "label": "positive"
        })
        
        gradient_creator = MagicMock(return_value=torch.randn(100))
        
        dataset = TextGradientTrainingDataset(
            training_data=training_data,
            tokenizer=tokenizer,
            gradient_creator=gradient_creator
        )
        
        # The padding function should use pad_token_id for 'input_ids'
        padding_value = dataset._get_padding_value("input_ids")
        assert padding_value == 999
        
        # Other keys should use 0
        padding_value_other = dataset._get_padding_value("attention_mask")
        assert padding_value_other == 0

    def test_create_gradient_training_dataset_respects_explicit_target_none(self):
        """Explicit target=None must not be replaced by TrainingArguments.target."""
        trainer = TextPredictionTrainer.__new__(TextPredictionTrainer)
        trainer._training_args = TrainingArguments(source="alternative", target="diff")

        tokenizer = MockTokenizer()
        model = MagicMock()
        model.tokenizer = tokenizer
        model.gradiend.torch_dtype = torch.float32
        model.gradiend.device_encoder = torch.device("cpu")
        model.gradient_creator = MagicMock(return_value=torch.randn(4))

        raw = MagicMock()
        raw.__len__ = MagicMock(return_value=1)

        default_dataset = trainer.create_gradient_training_dataset(raw, model)
        assert default_dataset.target == "diff"

        eval_dataset = trainer.create_gradient_training_dataset(raw, model, target=None)
        assert eval_dataset.target is None

    def test_create_gradient_training_dataset_uses_training_args_signal(self):
        trainer = TextPredictionTrainer.__new__(TextPredictionTrainer)
        trainer._training_args = TrainingArguments(signal=Signal.gradient())

        tokenizer = MockTokenizer()
        model = MagicMock()
        model.tokenizer = tokenizer
        model.gradiend.torch_dtype = torch.float32
        model.gradiend.device_encoder = torch.device("cpu")
        model.gradient_creator = MagicMock(return_value=torch.randn(4))

        raw = MagicMock()
        raw.__len__ = MagicMock(return_value=1)

        dataset = trainer.create_gradient_training_dataset(raw, model)

        assert dataset.signal == Signal.gradient()
        assert dataset.signals.ids == ("gradient",)

    def test_create_gradient_training_dataset_uses_activation_signal_extractor(self):
        trainer = TextPredictionTrainer.__new__(TextPredictionTrainer)
        trainer._training_args = TrainingArguments(
            signal=Signal.activation(token_selector="mask"),
            signal_scope=SignalScope.from_values(activation_sites=["embeddings"]),
        )

        tokenizer = MockTokenizer()
        model = MagicMock()
        model.base_model = SimpleMockModel(vocab_size=200, hidden_size=4)
        model.tokenizer = tokenizer
        model.gradiend.torch_dtype = torch.float32
        model.gradiend.device_encoder = torch.device("cpu")
        model.gradiend.input_dim = 4

        raw = MagicMock()
        raw.__len__ = MagicMock(return_value=1)
        raw.batch_size = 1
        raw.__getitem__ = MagicMock(return_value={
            "factual": {"input_ids": torch.tensor([101, 103, 102])},
            "alternative": {"input_ids": torch.tensor([101, 7, 103])},
            "template": "token_1 [MASK]",
            "input_text": "token_1 [MASK]",
            "label": "positive",
            "factual_token": "token_2",
            "alternative_token": "token_3",
        })

        dataset = trainer.create_gradient_training_dataset(raw, model)

        assert isinstance(dataset, TextActivationTrainingDataset)
        assert isinstance(dataset.signal_extractor, ActivationSignalExtractor)
        assert dataset.signal == Signal.activation(token_selector="mask")
        row = dataset[0]
        assert row["source"].shape == (4,)
        assert row["target"].shape == (4,)

    def test_text_activation_dataset_fills_prediction_slot_before_extracting(self):
        tokenizer = MockTokenizer()
        tokenizer.vocab.update({
            "The": 10,
            "person": 11,
            "he": 12,
            "she": 13,
            "runs": 14,
        })
        raw = TextTrainingDataset(
            data=pd.DataFrame({
                "masked": ["The person [MASK] runs"],
                "factual": ["he"],
                "alternative": ["she"],
                "factual_class": ["3SG"],
                "alternative_class": ["3PL"],
                "factual_id": ["3SG"],
                "alternative_id": ["3PL"],
                "label": [1.0],
                "feature_class_id": ["3SG->3PL"],
            }),
            tokenizer=tokenizer,
            batch_size=1,
        )

        class InputIdActivationExtractor:
            signal = Signal.activation(token_selector="prediction")

            def __init__(self):
                self.factual_inputs = None
                self.alternative_inputs = None

            def __call__(
                self,
                factual_inputs=None,
                alternative_inputs=None,
                *,
                requires_factual=True,
                requires_alternative=True,
            ):
                if factual_inputs is not None:
                    self.factual_inputs = factual_inputs
                if alternative_inputs is not None:
                    self.alternative_inputs = alternative_inputs
                factual = factual_inputs["input_ids"].float() if requires_factual else None
                alternative = alternative_inputs["input_ids"].float() if requires_alternative else None
                return SignalBatch.from_factual_alternative(
                    factual,
                    alternative,
                    signal_id="activation",
                )

        extractor = InputIdActivationExtractor()
        dataset = TextActivationTrainingDataset(
            raw,
            tokenizer,
            extractor,
            signal=Signal.activation(),
            source="diff",
            target="diff",
        )

        row = dataset[0]

        assert dataset.signal == Signal.activation(token_selector="prediction")
        assert tokenizer.mask_token_id not in extractor.factual_inputs["input_ids"].tolist()
        assert tokenizer.mask_token_id not in extractor.alternative_inputs["input_ids"].tolist()
        assert extractor.factual_inputs["prediction_mask"].sum().item() == 1
        assert extractor.alternative_inputs["prediction_mask"].sum().item() == 1
        assert row["source"].abs().sum().item() > 0

    def test_text_activation_dataset_fills_wordpiece_continuation_by_token_id(self):
        """WordPiece targets like ##ver must be inserted by id, not string-replaced."""
        tokenizer = MockTokenizer()
        tokenizer.vocab.update({
            "thie": 20,
            "##ver": 21,
            "y": 22,
            ".": 23,
        })
        tokenizer.unk_token_id = 1
        raw = TextTrainingDataset(
            data=pd.DataFrame({
                "masked": ["thie [MASK] y"],
                "factual": ["##ver"],
                "alternative": ["##ver"],
                "factual_class": ["neutral"],
                "alternative_class": ["neutral"],
                "factual_id": ["neutral"],
                "alternative_id": ["neutral"],
                "label": [0.0],
                "feature_class_id": ["neutral"],
            }),
            tokenizer=tokenizer,
            batch_size=1,
        )

        class InputIdActivationExtractor:
            signal = Signal.activation(token_selector="prediction")

            def __init__(self):
                self.factual_inputs = None

            def __call__(
                self,
                factual_inputs=None,
                alternative_inputs=None,
                *,
                requires_factual=True,
                requires_alternative=True,
            ):
                if factual_inputs is not None:
                    self.factual_inputs = factual_inputs
                factual = factual_inputs["input_ids"].float() if requires_factual else None
                alternative = (
                    alternative_inputs["input_ids"].float()
                    if requires_alternative and alternative_inputs is not None
                    else factual
                )
                return SignalBatch.from_factual_alternative(
                    factual,
                    alternative,
                    signal_id="activation",
                )

        extractor = InputIdActivationExtractor()
        dataset = TextActivationTrainingDataset(
            raw,
            tokenizer,
            extractor,
            signal=Signal.activation(),
            source="factual",
            target="diff",
        )

        row = dataset[0]

        assert tokenizer.mask_token_id not in extractor.factual_inputs["input_ids"].tolist()
        assert tokenizer.vocab["##ver"] in extractor.factual_inputs["input_ids"].tolist()
        assert extractor.factual_inputs["prediction_mask"].sum().item() == 1
        assert row["source"].numel() > 0
        pred_ids = extractor.factual_inputs["input_ids"][extractor.factual_inputs["prediction_mask"]].tolist()
        assert pred_ids == [tokenizer.vocab["##ver"]]

    def test_filled_prediction_from_template_splices_multi_token_targets(self):
        from gradiend.trainer.text.prediction.dataset import _filled_prediction_from_template

        tokenizer = MockTokenizer()
        tokenizer.vocab.update({"The": 10, "person": 11, "John": 12, "Smith": 13, "runs": 14})
        tokenizer.unk_token_id = 1

        item = _filled_prediction_from_template(
            tokenizer,
            template="The person [MASK] runs",
            target="John Smith",
            max_length=16,
        )
        ids = item["input_ids"].tolist()
        assert tokenizer.vocab["John"] in ids
        assert tokenizer.vocab["Smith"] in ids
        assert item["prediction_mask"].sum().item() == 2
        pred_ids = item["input_ids"][item["prediction_mask"]].tolist()
        assert pred_ids == [tokenizer.vocab["John"], tokenizer.vocab["Smith"]]

    def test_filled_prediction_from_template_fills_every_mask_slot(self):
        from gradiend.trainer.text.prediction.dataset import _filled_prediction_from_template

        tokenizer = MockTokenizer()
        tokenizer.vocab.update({
            "Sabrina": 30,
            "gave": 31,
            "no": 32,
            "indication": 33,
            "she": 34,
            "heard": 35,
            "us": 36,
            "but": 37,
            "i": 38,
            "knew": 39,
            "was": 40,
            "listening": 41,
            ".": 42,
        })
        tokenizer.unk_token_id = 1

        item = _filled_prediction_from_template(
            tokenizer,
            template="Sabrina gave no indication [MASK] heard us but i knew [MASK] was listening .",
            target="she",
            max_length=32,
        )
        ids = item["input_ids"].tolist()
        assert ids.count(tokenizer.vocab["she"]) == 2
        assert tokenizer.mask_token_id not in ids
        assert item["prediction_mask"].sum().item() == 2

    def test_filled_prediction_from_template_without_tokenizer_mask_token(self):
        """Dataset mask placeholder must work when the tokenizer has no MLM mask special."""
        from gradiend.trainer.text.prediction.dataset import _filled_prediction_from_template

        tokenizer = MockTokenizer()
        tokenizer.mask_token = None
        tokenizer.mask_token_id = None
        tokenizer.vocab.update({"The": 10, "person": 11, "he": 12, "runs": 13, "[MASK]": 103})

        item = _filled_prediction_from_template(
            tokenizer,
            template="The person [MASK] runs",
            target="he",
            max_length=16,
        )
        ids = item["input_ids"].tolist()
        assert tokenizer.vocab["he"] in ids
        assert 103 not in ids  # dataset placeholder must be replaced
        assert item["prediction_mask"].sum().item() == 1
        assert item["input_ids"][item["prediction_mask"]].tolist() == [tokenizer.vocab["he"]]

    def test_create_masked_pair_skips_wordpiece_continuations(self):
        from gradiend.trainer.text.prediction.dataset import create_masked_pair_from_text

        tokenizer = MockTokenizer()
        tokenizer.vocab.update({"thie": 20, "##ver": 21, "y": 22, "hello": 23, "world": 24})

        def tokenize(text, **kwargs):
            # Simulate BERT pieces for "thievery" plus two whole words.
            if "thievery" in text:
                return ["thie", "##ver", "y", "hello", "world"]
            return text.split()

        tokenizer.tokenize = tokenize
        pair = create_masked_pair_from_text(
            "thievery hello world",
            tokenizer,
            is_decoder_only_model=False,
            mask_token="[MASK]",
        )
        assert pair is not None
        masked, target = pair
        assert not str(target).startswith("##")
        assert "[MASK]" in masked

    def test_text_dataset_caching_uses_cache_key_fields(self, temp_dir):
        """Test that text dataset uses correct cache_key_fields for caching."""
        cache_dir = os.path.join(temp_dir, "cache")
        os.makedirs(cache_dir, exist_ok=True)
        
        tokenizer = MockTokenizer()
        training_data = MagicMock()
        training_data.__len__ = MagicMock(return_value=1)
        training_data.__getitem__ = MagicMock(return_value={
            "factual": {"input_ids": torch.tensor([1, 2, 3])},
            "alternative": {"input_ids": torch.tensor([4, 5, 6])},
            "input_text": "test text",
            "label": "positive"
        })
        
        gradient_creator = MagicMock(return_value=torch.randn(100))
        
        dataset = TextGradientTrainingDataset(
            training_data=training_data,
            tokenizer=tokenizer,
            gradient_creator=gradient_creator,
            cache_dir=cache_dir,
            use_cached_gradients=True
        )
        
        # Should use ['input_text', 'label'] as cache_key_fields
        assert dataset.cache_key_fields == ['input_text', 'label']
    
    def test_text_dataset_caching_no_cache_key_fields_when_disabled(self):
        """Test that cache_key_fields is None when caching is disabled."""
        tokenizer = MockTokenizer()
        training_data = MagicMock()
        training_data.__len__ = MagicMock(return_value=1)
        training_data.__getitem__ = MagicMock(return_value={
            "factual": {"input_ids": torch.tensor([1, 2, 3])},
            "alternative": {"input_ids": torch.tensor([4, 5, 6])},
            "input_text": "test",
            "label": "positive"
        })
        
        gradient_creator = MagicMock(return_value=torch.randn(100))
        
        dataset = TextGradientTrainingDataset(
            training_data=training_data,
            tokenizer=tokenizer,
            gradient_creator=gradient_creator,
            cache_dir=None,  # Caching disabled
            use_cached_gradients=False
        )
        
        # Should not set cache_key_fields when caching is disabled
        assert dataset.cache_key_fields == []
    
    def test_text_dataset_requires_input_text_and_label_for_caching(self, temp_dir):
        """Test that text dataset requires input_text and label when caching."""
        cache_dir = os.path.join(temp_dir, "cache")
        os.makedirs(cache_dir, exist_ok=True)
        
        tokenizer = MockTokenizer()
        
        # Create a proper mock that handles __getitem__ correctly
        class MockTrainingDataWithGetItem:
            def __init__(self):
                self.batch_size = 1
            
            def __len__(self):
                return 1
            
            def __getitem__(self, idx):
                # Return dict without input_text and label
                return {
                    "factual": {"input_ids": torch.tensor([1, 2, 3])},
                    "alternative": {"input_ids": torch.tensor([4, 5, 6])}
                    # Missing "input_text" and "label"
                }
        
        training_data = MockTrainingDataWithGetItem()
        
        gradient_creator = MagicMock(return_value=torch.randn(100))
        
        dataset = TextGradientTrainingDataset(
            training_data=training_data,
            tokenizer=tokenizer,
            gradient_creator=gradient_creator,
            cache_dir=cache_dir,
            use_cached_gradients=True
        )
        
        # Should raise KeyError when accessing batch without required cache keys
        with pytest.raises(KeyError, match="input_text|label"):
            _ = dataset[0]


class TestTextTrainingDataset:
    """Test TextTrainingDataset (text-specific training dataset)."""
    
    def test_text_training_dataset_creation(self):
        """Test that TextTrainingDataset can be created."""
        # Use string literal "masked" instead of constant to ensure pandas compatibility
        data = pd.DataFrame({
            "masked": ["Hello [MASK] world", "Test [MASK] sentence"],
            "factual": ["test1", "test2"],
            "alternative": ["other1", "other2"],
            "factual_class": ["class1", "class2"],
            "alternative_class": ["class2", "class1"],
            "factual_id": [1, 2],
            "alternative_id": [3, 4],
            "label": ["positive", "negative"],
            "feature_class_id": [1, 2]
        })
        
        tokenizer = MockTokenizer()
        tokenizer.mask_token = "[MASK]"
        
        dataset = TextTrainingDataset(
            data=data,
            tokenizer=tokenizer,
            batch_size=1,
            is_decoder_only_model=False,
            max_size=None
        )
        
        assert len(dataset) > 0
        assert dataset.tokenizer == tokenizer
        assert dataset.batch_size == 1

    def test_text_training_dataset_raises_when_insufficient_data_for_batch_size(self):
        """Creating a dataset with too few samples per subgroup raises a comprehensive ValueError."""
        # One sample per (feature_class_id, label) -> subgroups of size 1; batch_size=4 cannot be satisfied
        data = pd.DataFrame({
            "masked": ["Hello [MASK] world", "Other [MASK] text"],
            "factual": ["he", "they"],
            "alternative": ["they", "he"],
            "factual_class": ["3SG", "3PL"],
            "alternative_class": ["3PL", "3SG"],
            "factual_id": [1, 2],
            "alternative_id": [2, 1],
            "label": ["he", "they"],
            "feature_class_id": [0, 1],
        })
        tokenizer = MockTokenizer()
        tokenizer.mask_token = "[MASK]"
        tokenizer.mask_token_id = 103

        with pytest.raises(ValueError) as exc_info:
            TextTrainingDataset(
                data=data,
                tokenizer=tokenizer,
                batch_size=4,
                balance_column="feature_class_id",
            )
        msg = str(exc_info.value)
        assert "batch_size" in msg
        assert "4" in msg
        assert "1" in msg  # smallest subgroup has 1 sample
        assert "Use more training_data data" in msg or "reduce" in msg.lower()

    def test_text_training_dataset_max_size(self):
        """Test that max_size limits the number of samples."""
        data = pd.DataFrame({
            "masked": [f"Text {i} [MASK]" for i in range(100)],
            "factual": ["token"] * 100,
            "alternative": ["other"] * 100,
            "factual_class": ["class1"] * 100,
            "alternative_class": ["class2"] * 100,
            "factual_id": list(range(100)),
            "alternative_id": list(range(100, 200)),
            "label": ["positive"] * 100,
            "feature_class_id": [1] * 100
        })
        
        tokenizer = MockTokenizer()
        tokenizer.mask_token = "[MASK]"
        
        # Without max_size
        dataset_full = TextTrainingDataset(
            data=data,
            tokenizer=tokenizer,
            batch_size=1,
            max_size=None
        )
        # Length depends on batching logic, but should be <= 100
        assert len(dataset_full) <= 100
        
        # With max_size (seed is handled internally by parent class)
        dataset_limited = TextTrainingDataset(
            data=data,
            tokenizer=tokenizer,
            batch_size=1,
            max_size=50
        )
        # Should be limited to 50 samples
        assert len(dataset_limited) <= 50
    
    def test_text_training_dataset_max_size_downsampling(self):
        """Test that max_size downsamples the data."""
        data = pd.DataFrame({
            "masked": [f"Text {i} [MASK]" for i in range(100)],
            "factual": ["token"] * 100,
            "alternative": ["other"] * 100,
            "factual_class": ["class1"] * 100,
            "alternative_class": ["class2"] * 100,
            "factual_id": list(range(100)),
            "alternative_id": list(range(100, 200)),
            "label": ["positive"] * 100,
            "feature_class_id": [1] * 100
        })
        
        tokenizer = MockTokenizer()
        tokenizer.mask_token = "[MASK]"
        
        dataset = TextTrainingDataset(
            data=data,
            tokenizer=tokenizer,
            batch_size=1,
            max_size=30
        )
        
        # Should have at most 30 samples (downsampled)
        assert len(dataset) <= 30
    
    def test_text_training_dataset_batch_size(self):
        """Test that batch_size affects dataset length."""
        # Need multiple labels to create batches (batch_criterion groups by label)
        # TextTrainingDataset uses total_samples = total_batches * batch_size (or 100 * total_batches * batch_size if balance_column)
        data = pd.DataFrame({
            "masked": [f"Text {i} [MASK]" for i in range(20)],
            "factual": ["token"] * 20,
            "alternative": ["other"] * 20,
            "factual_class": ["class1"] * 20,
            "alternative_class": ["class2"] * 20,
            "label": ["positive"] * 10 + ["negative"] * 10,  # Need different labels for batching
            "feature_class_id": [1] * 20
        })
        
        tokenizer = MockTokenizer()
        tokenizer.mask_token = "[MASK]"
        
        # batch_size=1 - all items can be batched individually
        dataset_bs1 = TextTrainingDataset(
            data=data,
            tokenizer=tokenizer,
            batch_size=1
        )
        dataset_bs2 = TextTrainingDataset(
            data=data,
            tokenizer=tokenizer,
            batch_size=2
        )

        assert dataset_bs1.total_batches == 20
        assert dataset_bs2.total_batches == 10
        assert dataset_bs1.total_batches > dataset_bs2.total_batches
    
    def test_text_training_dataset_balance_column(self):
        """Test that balance_column affects batching."""
        # Need enough items with same label within each balance group for batching
        # TextTrainingDataset groups by batch_criterion (label by default), then batches
        data = pd.DataFrame({
            "masked": [f"Text {i} [MASK]" for i in range(8)],
            "factual": [f"token{i}" for i in range(8)],
            "alternative": [f"other{i}" for i in range(8)],
            "factual_class": ["class1"] * 4 + ["class2"] * 4,
            "alternative_class": ["class2"] * 4 + ["class1"] * 4,
            "factual_id": list(range(8)),
            "alternative_id": list(range(8, 16)),
            "label": ["positive"] * 8,  # Same label so they can be batched together
            "feature_class_id": [1] * 4 + [2] * 4  # Two balance groups
        })
        
        tokenizer = MockTokenizer()
        tokenizer.mask_token = "[MASK]"
        
        dataset = TextTrainingDataset(
            data=data,
            tokenizer=tokenizer,
            batch_size=2,
            balance_column="feature_class_id"
        )
        
        # Should batch by feature_class_id
        # With 2 items per class and batch_size=2, should get batches
        assert len(dataset) >= 1
    
    def test_text_training_dataset_decoder_only_pad_token(self):
        """Test that decoder-only models use eos_token as pad_token."""
        data = pd.DataFrame({
            "masked": ["Hello [MASK] world"],
            "factual": ["test"],
            "alternative": ["other"],
            "factual_class": ["class1"],
            "alternative_class": ["class2"],
            "factual_id": [1],
            "alternative_id": [2],
            "label": ["positive"],
            "feature_class_id": [1]
        })
        
        tokenizer = MockTokenizer()
        tokenizer.pad_token = None
        tokenizer.eos_token = "<|endoftext|>"
        tokenizer.eos_token_id = 50256
        
        dataset = TextTrainingDataset(
            data=data,
            tokenizer=tokenizer,
            batch_size=1,
            is_decoder_only_model=True
        )
        
        # Should set pad_token to eos_token for decoder-only models
        assert tokenizer.pad_token == "<|endoftext|>"
    
    def test_text_training_dataset_returns_correct_structure(self):
        """Test that TextTrainingDataset returns items with correct structure."""
        data = pd.DataFrame({
            "masked": ["Hello [MASK] world"],
            "factual": ["test"],
            "alternative": ["other"],
            "factual_class": ["class1"],
            "alternative_class": ["class2"],
            "factual_id": [1],
            "alternative_id": [2],
            "label": ["positive"],
            "feature_class_id": [1]
        })
        
        tokenizer = MockTokenizer()
        tokenizer.mask_token = "[MASK]"
        tokenizer.mask_token_id = 103
        
        dataset = TextTrainingDataset(
            data=data,
            tokenizer=tokenizer,
            batch_size=1,
            is_decoder_only_model=False
        )
        
        item = dataset[0]
        
        # Should have factual and alternative keys
        assert "factual" in item
        assert "alternative" in item
        
        # Factual and alternative should have input_ids, attention_mask, labels
        assert "input_ids" in item["factual"]
        assert "attention_mask" in item["factual"]
        assert "labels" in item["factual"]
        
        assert "input_ids" in item["alternative"]
        assert "attention_mask" in item["alternative"]
        assert "labels" in item["alternative"]

    def test_text_training_dataset_labels_all_classic_mlm_prediction_masks(self):
        """Each classic MLM placeholder is a supervised site for the same target."""
        dataset = TextTrainingDataset(
            data=pd.DataFrame({
                "masked": ["[MASK] said that [MASK] was late"],
                "factual": ["token_1"],
                "alternative": ["token_2"],
                "factual_class": ["class1"],
                "alternative_class": ["class2"],
                "factual_id": [1],
                "alternative_id": [2],
                "label": ["positive"],
                "feature_class_id": [1],
            }),
            tokenizer=MockTokenizer(),
            batch_size=1,
            is_decoder_only_model=False,
        )

        item = dataset._create_item("[MASK] said that [MASK] was late", "token_1")
        labels = item["labels"]
        assert labels[labels != -100].tolist() == [1, 1]

    def test_text_training_dataset_expands_one_classic_mlm_mask_for_multi_token_target(self):
        """A single MLM placeholder may stand for a contiguous multi-token target span."""
        tokenizer = MockTokenizer()
        dataset = TextTrainingDataset(
            data=pd.DataFrame({
                "masked": ["Hello [MASK] world"],
                "factual": ["token_1 token_2"],
                "alternative": ["token_3 token_4"],
                "factual_class": ["class1"],
                "alternative_class": ["class2"],
                "factual_id": [1],
                "alternative_id": [2],
                "label": ["positive"],
                "feature_class_id": [1],
            }),
            tokenizer=tokenizer,
            batch_size=1,
            is_decoder_only_model=False,
        )

        item = dataset._create_item("Hello [MASK] world", "token_1 token_2")

        labels = item["labels"]
        assert labels[labels != -100].tolist() == [1, 2]

    def test_text_training_dataset_expands_all_classic_mlm_masks_for_multi_token_target(self):
        """Multi-site multi-token cloze expands each placeholder to the same target span."""
        dataset = TextTrainingDataset(
            data=pd.DataFrame({
                "masked": ["[MASK] met [MASK] today"],
                "factual": ["token_1 token_2"],
                "alternative": ["token_3 token_4"],
                "factual_class": ["class1"],
                "alternative_class": ["class2"],
                "factual_id": [1],
                "alternative_id": [2],
                "label": ["positive"],
                "feature_class_id": [1],
            }),
            tokenizer=MockTokenizer(),
            batch_size=1,
            is_decoder_only_model=False,
        )

        item = dataset._create_item("[MASK] met [MASK] today", "token_1 token_2")
        labels = item["labels"]
        assert labels[labels != -100].tolist() == [1, 2, 1, 2]

    def test_text_training_dataset_classic_mlm_per_site_targets(self):
        """A sequence of targets assigns one target per prediction site."""
        dataset = TextTrainingDataset(
            data=pd.DataFrame({
                "masked": ["[MASK] said that [MASK] was late"],
                "factual": ["token_1"],
                "alternative": ["token_2"],
                "factual_class": ["class1"],
                "alternative_class": ["class2"],
                "factual_id": [1],
                "alternative_id": [2],
                "label": ["positive"],
                "feature_class_id": [1],
            }),
            tokenizer=MockTokenizer(),
            batch_size=1,
            is_decoder_only_model=False,
        )

        item = dataset._create_item(
            "[MASK] said that [MASK] was late",
            ["token_1", "token_2"],
        )
        labels = item["labels"]
        assert labels[labels != -100].tolist() == [1, 2]

    def test_text_training_dataset_classic_mlm_per_site_target_length_mismatch(self):
        """Per-site target sequences must match the placeholder count."""
        dataset = TextTrainingDataset(
            data=pd.DataFrame({
                "masked": ["[MASK] said that [MASK] was late"],
                "factual": ["token_1"],
                "alternative": ["token_2"],
                "factual_class": ["class1"],
                "alternative_class": ["class2"],
                "factual_id": [1],
                "alternative_id": [2],
                "label": ["positive"],
                "feature_class_id": [1],
            }),
            tokenizer=MockTokenizer(),
            batch_size=1,
            is_decoder_only_model=False,
        )

        with pytest.raises(ValueError, match="per-site targets must match"):
            dataset._create_item("[MASK] said that [MASK] was late", ["token_1"])

    def test_text_training_dataset_classic_mlm_per_site_multi_token_targets(self):
        """Per-site targets may differ in tokenized length."""
        dataset = TextTrainingDataset(
            data=pd.DataFrame({
                "masked": ["[MASK] met [MASK] today"],
                "factual": ["token_1"],
                "alternative": ["token_2"],
                "factual_class": ["class1"],
                "alternative_class": ["class2"],
                "factual_id": [1],
                "alternative_id": [2],
                "label": ["positive"],
                "feature_class_id": [1],
            }),
            tokenizer=MockTokenizer(),
            batch_size=1,
            is_decoder_only_model=False,
        )

        item = dataset._create_item(
            "[MASK] met [MASK] today",
            ["token_1 token_2", "token_3"],
        )
        labels = item["labels"]
        assert labels[labels != -100].tolist() == [1, 2, 3]

    def test_text_training_dataset_feature_class_id_preserved(self):
        """Test that feature_class_id is preserved in items."""
        data = pd.DataFrame({
            "masked": ["Hello [MASK] world"],
            "factual": ["test"],
            "alternative": ["other"],
            "factual_class": ["class1"],
            "alternative_class": ["class2"],
            "factual_id": [1],
            "alternative_id": [2],
            "label": ["positive"],
            "feature_class_id": [42]
        })
        
        tokenizer = MockTokenizer()
        tokenizer.mask_token = "[MASK]"
        
        dataset = TextTrainingDataset(
            data=data,
            tokenizer=tokenizer,
            batch_size=1
        )
        
        item = dataset[0]
        
        # Should preserve feature_class_id
        assert "feature_class_id" in item
        assert item["feature_class_id"] == 42
    
    def test_text_training_dataset_label_preserved(self):
        """Test that label is preserved in items."""
        data = pd.DataFrame({
            "masked": ["Hello [MASK] world"],
            "factual": ["test"],
            "alternative": ["other"],
            "factual_class": ["class1"],
            "alternative_class": ["class2"],
            "factual_id": [1],
            "alternative_id": [2],
            "label": ["positive"],
            "feature_class_id": [1]
        })
        
        tokenizer = MockTokenizer()
        tokenizer.mask_token = "[MASK]"
        
        dataset = TextTrainingDataset(
            data=data,
            tokenizer=tokenizer,
            batch_size=1,
            target_key="label"
        )
        
        item = dataset[0]
        
        # Should preserve label
        assert "label" in item
        assert item["label"] == "positive"
    
    def test_text_training_dataset_max_length(self):
        """Test that max_length limits sequence length."""
        data = pd.DataFrame({
            "masked": ["Hello [MASK] world"] * 10,
            "factual": ["test"] * 10,
            "alternative": ["other"] * 10,
            "factual_class": ["class1"] * 10,
            "alternative_class": ["class2"] * 10,
            "factual_id": list(range(10)),
            "alternative_id": list(range(10, 20)),
            "label": ["positive"] * 10,
            "feature_class_id": [1] * 10
        })
        
        tokenizer = MockTokenizer()
        tokenizer.mask_token = "[MASK]"
        
        dataset = TextTrainingDataset(
            data=data,
            tokenizer=tokenizer,
            batch_size=1,
            max_length=128
        )
        
        item = dataset[0]
        
        # input_ids should be truncated/padded to max_length
        assert item["factual"]["input_ids"].shape[0] <= 128
        assert item["alternative"]["input_ids"].shape[0] <= 128


class TestTextDatasetDataLoadingVariations:
    """Test data loading variations like add_identity_for_other_classes and max_size."""
    
    def test_max_size_limits_per_feature_class(self):
        """Test that max_size can limit samples per feature_class_id."""
        # This tests the behavior when max_size is applied per feature_class_id
        # in the trainer's data loading methods
        data = pd.DataFrame({
            "masked": [f"Text {i} [MASK]" for i in range(100)],
            "factual": ["token"] * 100,
            "alternative": ["other"] * 100,
            "factual_class": ["class1"] * 50 + ["class2"] * 50,
            "alternative_class": ["class2"] * 50 + ["class1"] * 50,
            "factual_id": list(range(100)),
            "alternative_id": list(range(100, 200)),
            "label": ["positive"] * 50 + ["negative"] * 50,
            "feature_class_id": [1] * 50 + [2] * 50
        })
        
        tokenizer = MockTokenizer()
        tokenizer.mask_token = "[MASK]"
        
        # max_size should limit total samples
        # This is typically handled in the trainer, not the dataset itself
        # Note: seed is handled by parent class, not passed directly
        dataset = TextTrainingDataset(
            data=data,
            tokenizer=tokenizer,
            batch_size=1,
            max_size=30  # Total max_size
        )
        
        # Should have at most 30 samples total (downsampled)
        assert len(dataset) <= 30
    
    def test_add_identity_for_other_classes_requires_classes(self):
        """Test that add_identity_for_other_classes requires class definitions."""
        # This is typically handled in the trainer, not the dataset
        # The dataset itself doesn't handle add_identity_for_other_classes
        # It's a TrainingArguments parameter that affects data loading
        
        # We can test that the dataset works with identity samples if they're provided
        data = pd.DataFrame({
            "masked": ["Hello [MASK] world"],
            "factual": ["neutral_data"],
            "alternative": ["neutral_data"],
            "factual_class": ["neutral_data"],
            "alternative_class": ["neutral_data"],
            "factual_id": [0],
            "alternative_id": [0],
            "label": ["neutral_data"],  # Identity/neutral_data class
            "feature_class_id": [0]  # Identity class ID
        })
        
        tokenizer = MockTokenizer()
        tokenizer.mask_token = "[MASK]"
        
        dataset = TextTrainingDataset(
            data=data,
            tokenizer=tokenizer,
            batch_size=1
        )
        
        # Should work fine with identity samples
        item = dataset[0]
        assert "factual" in item
        assert "alternative" in item
    
    def test_dataset_handles_multiple_feature_classes(self):
        """Test that dataset handles multiple feature_class_id values."""
        data = pd.DataFrame({
            "masked": [f"Text {i} [MASK]" for i in range(20)],
            "factual": ["token"] * 20,
            "alternative": ["other"] * 20,
            "factual_class": ["class1"] * 10 + ["class2"] * 10,
            "alternative_class": ["class2"] * 10 + ["class1"] * 10,
            "factual_id": list(range(20)),
            "alternative_id": list(range(20, 40)),
            "label": ["positive"] * 10 + ["negative"] * 10,
            "feature_class_id": [1] * 10 + [2] * 10
        })
        
        tokenizer = MockTokenizer()
        tokenizer.mask_token = "[MASK]"
        
        dataset = TextTrainingDataset(
            data=data,
            tokenizer=tokenizer,
            batch_size=2,
            balance_column="feature_class_id"
        )
        
        # Should handle multiple classes
        assert len(dataset) >= 1
        
        # Should preserve feature_class_id in items
        for i in range(min(5, len(dataset))):
            item = dataset[i]
            assert "feature_class_id" in item
