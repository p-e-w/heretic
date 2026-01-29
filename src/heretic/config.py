# SPDX-License-Identifier: AGPL-3.0-or-later
# Copyright (C) 2025  Philipp Emanuel Weidmann <pew@worldwidemann.com>

from enum import Enum
from typing import Dict

from optuna.study import StudyDirection
from pydantic import BaseModel, Field, field_validator
from pydantic.dataclasses import dataclass
from pydantic_settings import (
    BaseSettings,
    CliSettingsSource,
    EnvSettingsSource,
    PydanticBaseSettingsSource,
    SettingsConfigDict,
    TomlConfigSettingsSource,
)


class QuantizationMethod(str, Enum):
    NONE = "none"
    BNB_4BIT = "bnb_4bit"


class DatasetSpecification(BaseModel):
    dataset: str = Field(
        description="Hugging Face dataset ID, or path to dataset on disk."
    )

    split: str = Field(description="Portion of the dataset to use.")

    column: str = Field(description="Column in the dataset that contains the prompts.")

    prefix: str = Field(
        default="",
        description="Text to prepend to each prompt.",
    )

    suffix: str = Field(
        default="",
        description="Text to append to each prompt.",
    )

    system_prompt: str | None = Field(
        default=None,
        description="System prompt to use with the prompts (overrides global system prompt if set).",
    )

    residual_plot_label: str | None = Field(
        default=None,
        description="Label to use for the dataset in plots of residual vectors.",
    )

    residual_plot_color: str | None = Field(
        default=None,
        description="Matplotlib color to use for the dataset in plots of residual vectors.",
    )


@dataclass(frozen=True)
class ScorerConfig:
    """
    Configuration for a scorer plugin.

    TOML format:
    - { plugin = "<plugin>", direction = <direction>, scale = <scale>, instance_name = "<optional>" }
    """

    plugin: str
    direction: StudyDirection
    scale: float
    instance_name: str | None = None

    @field_validator("direction", mode="before")
    @classmethod
    def parse_direction(cls, v):
        if isinstance(v, StudyDirection):
            return v
        if isinstance(v, int):
            return StudyDirection(v)
        if isinstance(v, str):
            key = v.strip().upper()
            try:
                return StudyDirection[key]
            except KeyError as e:
                raise ValueError(f"Unknown direction, error: {e}")
        else:
            raise ValueError(
                'Direction must be one of "minimize", "maximize", "not_set"'
            )


class Settings(BaseSettings):
    # We intentionally allow extra keys so users can provide plugin-specific
    # configuration in TOML tables like `[scorer.RefusalRate]` which are later
    # consumed via `settings.model_extra` (see `Evaluator._get_plugin_namespace`).
    model_config = SettingsConfigDict(extra="allow")

    model: str = Field(description="Hugging Face model ID, or path to model on disk.")

    evaluate_model: str | None = Field(
        default=None,
        description="If this model ID or path is set, then instead of abliterating the main model, evaluate this model relative to the main model.",
    )

    dtypes: list[str] = Field(
        default=[
            # In practice, "auto" almost always means bfloat16.
            "auto",
            # If that doesn't work (e.g. on pre-Ampere hardware), fall back to float16.
            "float16",
            # If "auto" resolves to float32, and that fails because it is too large,
            # and float16 fails due to range issues, try bfloat16.
            "bfloat16",
            # If neither of those work, fall back to float32 (which will of course fail
            # if that was the dtype "auto" resolved to).
            "float32",
        ],
        description="List of PyTorch dtypes to try when loading model tensors. If loading with a dtype fails, the next dtype in the list will be tried.",
    )

    device_map: str | Dict[str, int | str] = Field(
        default="auto",
        description="Device map to pass to Accelerate when loading the model.",
    )

    max_memory: Dict[str, str] | None = Field(
        default=None,
        description="Maximum memory to allocate per device (e.g., {'0': '20GB', 'cpu': '64GB'}).",
    )

    trust_remote_code: bool | None = Field(
        default=None,
        description="Whether to trust remote code when loading the model.",
    )

    quantization: QuantizationMethod = Field(
        default=QuantizationMethod.NONE,
        description="Quantization method to use when loading the model. Options: 'none' (no quantization), 'bnb_4bit' (4-bit quantization using bitsandbytes).",
    )

    batch_size: int = Field(
        default=0,  # auto
        description="Number of input sequences to process in parallel (0 = auto).",
    )

    max_batch_size: int = Field(
        default=128,
        description="Maximum batch size to try when automatically determining the optimal batch size.",
    )

    max_response_length: int = Field(
        default=100,
        description="Maximum number of tokens to generate for each response.",
    )

    print_residual_geometry: bool = Field(
        default=False,
        description="Whether to print detailed information about residuals and refusal directions.",
    )

    plot_residuals: bool = Field(
        default=False,
        description="Whether to generate plots showing PaCMAP projections of residual vectors.",
    )

    residual_plot_path: str = Field(
        default="plots",
        description="Base path to save plots of residual vectors to.",
    )

    residual_plot_title: str = Field(
        default='PaCMAP Projection of Residual Vectors for "Harmless" and "Harmful" Prompts',
        description="Title placed above plots of residual vectors.",
    )

    residual_plot_style: str = Field(
        default="dark_background",
        description="Matplotlib style sheet to use for plots of residual vectors.",
    )

    scorers: list[ScorerConfig] = Field(
        default_factory=list,
        description=(
            "List of scorer plugin configs. Each entry is an object"
            " {plugin=<plugin>, direction=<direction>, scale=<scale>}."
            " <direction> is one of {0 (NOT_SET = do not optimize), 1 (MINIMIZE), 2 (MAXIMIZE)}."
        ),
    )

    n_trials: int = Field(
        default=200,
        description="Number of abliteration trials to run during optimization.",
    )

    n_startup_trials: int = Field(
        default=60,
        description="Number of trials that use random sampling for the purpose of exploration.",
    )

    study_checkpoint_dir: str = Field(
        default="checkpoints",
        description="Directory to save and load study progress to/from:",
    )
    system_prompt: str = Field(
        default="You are a helpful assistant.",
        description="System prompt to use when prompting the model.",
    )

    good_prompts: DatasetSpecification = Field(
        default=DatasetSpecification(
            dataset="mlabonne/harmless_alpaca",
            split="train[:400]",
            column="text",
            residual_plot_label='"Harmless" prompts',
            residual_plot_color="royalblue",
        ),
        description="Dataset of prompts that tend to not result in refusals (used for calculating refusal directions).",
    )

    bad_prompts: DatasetSpecification = Field(
        default=DatasetSpecification(
            dataset="mlabonne/harmful_behaviors",
            split="train[:400]",
            column="text",
            residual_plot_label='"Harmful" prompts',
            residual_plot_color="darkorange",
        ),
        description="Dataset of prompts that tend to result in refusals (used for calculating refusal directions).",
    )

    @classmethod
    def settings_customise_sources(
        cls,
        settings_cls: type[BaseSettings],
        init_settings: PydanticBaseSettingsSource,
        env_settings: PydanticBaseSettingsSource,
        dotenv_settings: PydanticBaseSettingsSource,
        file_secret_settings: PydanticBaseSettingsSource,
    ) -> tuple[PydanticBaseSettingsSource, ...]:
        return (
            init_settings,  # Used during resume - should override *all* other sources.
            CliSettingsSource(
                settings_cls,
                cli_parse_args=True,
                cli_implicit_flags=True,
                cli_kebab_case=True,
            ),
            EnvSettingsSource(settings_cls, env_prefix="HERETIC_"),
            dotenv_settings,
            file_secret_settings,
            TomlConfigSettingsSource(settings_cls, toml_file="config.toml"),
        )
