from __future__ import annotations

import models.mlp_mixer.expert_linear_adaptive.config as config
from emperor.config import BaseOptions
from emperor.datasets.text.bert_pretraining import WikiText103BertHierarchical
from emperor.layers import LayerNormPositionOptions
from model_runtime.packages import (
    BuilderBackedExperimentPresetsBase,
    PresetDefinition,
)
from model_runtime.runs import ExperimentBase

from .config_builder import MlpMixerExpertLinearAdaptiveConfigBuilder
from .runtime_defaults import runtime_from_flat


def default_patch_size_for_dataset(dataset: type) -> int:
    image_height = dataset.default_height
    if (
        image_height >= config.IMAGE_HEIGHT
        and image_height % config.IMAGE_PATCH_SIZE == 0
    ):
        return config.IMAGE_PATCH_SIZE
    for patch_size in (16, 8, 4, 2, 1):
        if image_height % patch_size == 0:
            return patch_size
    return 1


class ExperimentPreset(BaseOptions):
    BASELINE = 1
    POST_NORM = 2
    RECURRENT = 3
    RECURRENT_CONTROLLER = 4
    GATING = 5
    HALTING = 6
    MEMORY = 7
    GATING_HALTING_MEMORY = 8
    ADAPTIVE = 9
    TOP_1_EXPERT = 10
    EXPERT_AUXILIARY_LOSS = 11


_PRESET_DEFINITIONS = {
    ExperimentPreset.BASELINE: PresetDefinition(
        preset_values={},
        description=(
            "Eight pre-normalized MLP-Mixer blocks with routed adaptive-linear "
            "experts in both mixer branches, mean pooling, and no class token or "
            "positional embedding."
        ),
    ),
    ExperimentPreset.POST_NORM: PresetDefinition(
        preset_values={"layer_norm_position": LayerNormPositionOptions.AFTER},
        description="MLP-Mixer blocks with post-normalized residual branches.",
    ),
    ExperimentPreset.RECURRENT: PresetDefinition(
        preset_values={"recurrent_flag": True},
        description="Reuses the Mixer block stack for recurrent refinement.",
    ),
    ExperimentPreset.RECURRENT_CONTROLLER: PresetDefinition(
        preset_values={
            "recurrent_flag": True,
            "recurrent_stack_gate_flag": True,
        },
        description="Recurrent Mixer refinement with a learned step controller.",
    ),
    ExperimentPreset.GATING: PresetDefinition(
        preset_values={"stack_gate_flag": True},
        description="Mixer blocks with learned output gates.",
    ),
    ExperimentPreset.HALTING: PresetDefinition(
        preset_values={"stack_halting_flag": True},
        description="Mixer blocks with adaptive-computation halting.",
    ),
    ExperimentPreset.MEMORY: PresetDefinition(
        preset_values={"memory_flag": True},
        description="Mixer blocks with shared dynamic memory.",
    ),
    ExperimentPreset.GATING_HALTING_MEMORY: PresetDefinition(
        preset_values={
            "stack_gate_flag": True,
            "stack_halting_flag": True,
            "memory_flag": True,
        },
        description="Mixer blocks with gates, halting, and shared dynamic memory.",
    ),
    ExperimentPreset.ADAPTIVE: PresetDefinition(
        preset_values={"diagonal_option_flag": True},
        description="Input-adaptive affine layers inside every selected expert.",
    ),
    ExperimentPreset.TOP_1_EXPERT: PresetDefinition(
        preset_values={
            "top_k": 1,
            "sampler_normalize_probabilities_flag": False,
        },
        description="Top-1 routing to adaptive token and channel experts.",
    ),
    ExperimentPreset.EXPERT_AUXILIARY_LOSS: PresetDefinition(
        preset_values={"sampler_switch_loss_weight": 0.01},
        description="Adaptive experts with switch load-balancing loss.",
    ),
}


class ExperimentPresets(BuilderBackedExperimentPresetsBase):
    def __init__(self) -> None:
        super().__init__(
            _PRESET_DEFINITIONS,
            builder_type=MlpMixerExpertLinearAdaptiveConfigBuilder,
            default_preset=ExperimentPreset.BASELINE,
            runtime_factory=runtime_from_flat,
        )

    def _dataset_config(self, dataset: type) -> dict:
        dataset_config = super()._dataset_config(dataset)
        if issubclass(dataset, WikiText103BertHierarchical):
            return {
                **dataset_config,
                "hierarchical_masked_word_flag": True,
                "sequence_length": dataset.sequence_length,
                "token_mixer_soft_moe_flag": True,
            }
        return {
            **dataset_config,
            "image_patch_size": default_patch_size_for_dataset(dataset),
            "input_channels": dataset.num_channels,
            "image_height": dataset.default_height,
            "output_dim": dataset.num_classes,
        }


class Experiment(ExperimentBase):
    """Package-local Run Experiment Adapter."""

    def __init__(
        self,
        experiment_preset: ExperimentPreset | None = None,
        experiment_task=None,
        *,
        model_package,
        run_artifacts=None,
    ) -> None:
        super().__init__(
            experiment_preset=experiment_preset,
            experiment_task=experiment_task,
            model_package=model_package,
            run_artifacts=run_artifacts,
        )


__all__ = ["Experiment", "ExperimentPreset", "ExperimentPresets"]
