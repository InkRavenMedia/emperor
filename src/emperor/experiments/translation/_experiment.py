from __future__ import annotations

from typing import TYPE_CHECKING

import torch
import torch.nn as nn
from lightning import LightningModule
from torch import Tensor

from emperor.experiments._auxiliary_loss import AuxiliaryLoss

from ._config_validation import _TranslationConfigValidator
from ._metrics import _corpus_bleu, _translation_step_metrics
from ._records import TranslationBatch, TranslationStepOutput

if TYPE_CHECKING:
    from emperor.config import ModelConfig


class TranslationExperiment(LightningModule):
    """Shared teacher-forced training and corpus evaluation for translation models."""

    VALIDATOR = _TranslationConfigValidator

    def __init__(self, cfg: ModelConfig) -> None:
        super().__init__()
        self.cfg = cfg
        resolved_config = self.VALIDATOR.resolve(cfg)
        self.learning_rate = resolved_config.learning_rate
        self.vocab_size = resolved_config.vocab_size
        self.model_dim = resolved_config.model_dim
        self.pad_token_id = resolved_config.pad_token_id
        self.label_smoothing = resolved_config.label_smoothing
        self.warmup_steps = resolved_config.warmup_steps
        self.generation_metrics_flag = resolved_config.generation_metrics_flag
        self.loss_fn = nn.CrossEntropyLoss(
            ignore_index=self.pad_token_id,
            label_smoothing=self.label_smoothing,
        )
        self.nll_fn = nn.CrossEntropyLoss(ignore_index=self.pad_token_id)
        self._validation_predictions: list[str] = []
        self._validation_references: list[str] = []
        self._test_predictions: list[str] = []
        self._test_references: list[str] = []
        self._auxiliary_loss = AuxiliaryLoss("Translation")

    def training_step(self, batch: TranslationBatch, batch_idx: int) -> Tensor:
        output = self._model_step_outputs(batch)
        self._log_step("train", output, prog_bar=True)
        return output.total_loss

    def validation_step(self, batch: TranslationBatch, batch_idx: int) -> Tensor:
        output = self._model_step_outputs(batch)
        self._log_step("validation", output, prog_bar=True)
        self._collect_generation("validation", batch)
        return output.total_loss

    def test_step(self, batch: TranslationBatch, batch_idx: int) -> Tensor:
        output = self._model_step_outputs(batch)
        self._log_step("test", output, prog_bar=False)
        self._collect_generation("test", batch)
        return output.total_loss

    def on_validation_epoch_start(self) -> None:
        self._validation_predictions.clear()
        self._validation_references.clear()

    def on_validation_epoch_end(self) -> None:
        self._log_corpus_bleu(
            "validation",
            self._validation_predictions,
            self._validation_references,
        )

    def on_test_epoch_start(self) -> None:
        self._test_predictions.clear()
        self._test_references.clear()

    def on_test_epoch_end(self) -> None:
        self._log_corpus_bleu(
            "test",
            self._test_predictions,
            self._test_references,
        )

    def _model_step(self, batch: TranslationBatch) -> Tensor:
        return self._model_step_outputs(batch).total_loss

    def _model_step_outputs(self, batch: TranslationBatch) -> TranslationStepOutput:
        source_ids, target_ids = self._unpack_batch(batch)
        source_ids = source_ids.to(self.device)
        target_ids = target_ids.to(self.device)
        target_input_ids = target_ids[:, :-1]
        labels = target_ids[:, 1:]
        logits, auxiliary_loss = self._validate_model_output(
            self.forward_for_input_tokens(source_ids, target_input_ids),
            labels,
        )
        flat_logits = logits.reshape(-1, logits.size(-1))
        flat_labels = labels.reshape(-1)
        smoothed_loss = self.loss_fn(flat_logits, flat_labels)
        nll = self.nll_fn(flat_logits, flat_labels)
        total_loss = smoothed_loss + auxiliary_loss
        return TranslationStepOutput(
            total_loss=total_loss,
            nll=nll,
            logits=logits,
            labels=labels,
            auxiliary_loss=auxiliary_loss,
        )

    def forward_for_input_tokens(
        self, source_ids: Tensor, target_input_ids: Tensor
    ) -> tuple[Tensor, Tensor | None]:
        """Return predictions aligned with the teacher-forced target inputs."""
        return self(source_ids, target_input_ids)

    def _unpack_batch(self, batch: TranslationBatch) -> TranslationBatch:
        if len(batch) != 2:
            raise ValueError(
                "TranslationExperiment batches must contain (source_ids, target_ids)."
            )
        source_ids, target_ids = batch
        if (
            not isinstance(source_ids, Tensor)
            or not isinstance(target_ids, Tensor)
            or source_ids.ndim != 2
            or target_ids.ndim != 2
        ):
            raise ValueError(
                "Translation source and target IDs must be rank-2 tensors."
            )
        if target_ids.size(1) < 2:
            raise ValueError(
                "Translation target sequences must contain at least 2 IDs."
            )
        if source_ids.size(0) != target_ids.size(0):
            raise ValueError(
                "Translation source and target IDs must share the batch dimension."
            )
        return source_ids, target_ids

    def _validate_model_output(
        self,
        output: object,
        labels: Tensor,
    ) -> tuple[Tensor, Tensor]:
        if not isinstance(output, tuple) or len(output) != 2:
            raise ValueError(
                "Translation outputs must be a two-item tuple containing "
                "(logits, auxiliary_loss)."
            )
        logits, auxiliary_loss = output
        if not isinstance(logits, Tensor) or logits.ndim != 3:
            raise ValueError(
                "Translation logits must be a rank-3 tensor with shape "
                "[batch, target sequence, vocabulary]."
            )
        if logits.shape[:2] != labels.shape:
            raise ValueError(
                "Translation logits and labels must share batch and target "
                "sequence dimensions."
            )
        if logits.size(-1) != self.vocab_size:
            raise ValueError(
                "Translation logits vocabulary dimension must equal "
                f"config.output_dim ({self.vocab_size}), received "
                f"{logits.size(-1)}."
            )
        resolved_auxiliary_loss = self._auxiliary_loss.resolve(
            auxiliary_loss,
            reference=logits,
        )
        return logits, resolved_auxiliary_loss

    def _log_step(
        self,
        stage: str,
        output: TranslationStepOutput,
        *,
        prog_bar: bool,
    ) -> None:
        self.log_dict(
            _translation_step_metrics(stage, output, self.pad_token_id),
            prog_bar=prog_bar,
            on_step=stage == "train",
            on_epoch=True,
            batch_size=output.labels.size(0),
        )

    def _collect_generation(
        self,
        stage: str,
        batch: TranslationBatch,
    ) -> None:
        if not self.generation_metrics_flag:
            return
        datamodule = self._translation_datamodule()
        if datamodule is None or not hasattr(datamodule, "decode_batch"):
            return
        source_ids, target_ids = batch
        generated_ids = self.generate(
            source_ids.to(self.device),
            max_length=target_ids.size(1),
        )
        predictions = datamodule.decode_batch(generated_ids.detach().cpu())
        references = datamodule.decode_batch(target_ids.detach().cpu())
        if stage == "validation":
            self._validation_predictions.extend(predictions)
            self._validation_references.extend(references)
        else:
            self._test_predictions.extend(predictions)
            self._test_references.extend(references)

    def _translation_datamodule(self):
        trainer = getattr(self, "_trainer", None)
        return getattr(trainer, "datamodule", None) if trainer is not None else None

    def _log_corpus_bleu(
        self,
        stage: str,
        predictions: list[str],
        references: list[str],
    ) -> None:
        if not self.generation_metrics_flag or not predictions:
            return
        bleu = _corpus_bleu(predictions, references, self.device)
        self.log(f"{stage}/bleu", bleu, prog_bar=True, on_epoch=True)

    def configure_optimizers(self):
        optimizer = torch.optim.Adam(
            self.parameters(),
            lr=self.learning_rate,
            betas=(0.9, 0.98),
            eps=1e-9,
        )

        def inverse_square_root_schedule(step: int) -> float:
            safe_step = max(1, step + 1)
            return self.model_dim**-0.5 * min(
                safe_step**-0.5,
                safe_step * self.warmup_steps**-1.5,
            )

        scheduler = torch.optim.lr_scheduler.LambdaLR(
            optimizer,
            lr_lambda=inverse_square_root_schedule,
        )
        return {
            "optimizer": optimizer,
            "lr_scheduler": {
                "scheduler": scheduler,
                "interval": "step",
                "frequency": 1,
            },
        }
