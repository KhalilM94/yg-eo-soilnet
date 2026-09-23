"""Write the settings a trial drew into a copy of the model-list entry.

This is the whole connection between the search and the rest of the project. A search space names
each setting with a path - ``model.dropout``, ``trainer.max_epochs`` - and each one is written into
the matching part of a copied entry. Nothing else is touched.
"""

from __future__ import annotations

from typing import Any, Iterable, Mapping

import numpy as np

# Dotted prefix -> the registry section it writes to. `callbacks` is handled separately because it
# nests one level deeper (callbacks.<group>.<key>).
PREFIX_SECTIONS = {
    "model": "init_args",
    "datamodule": "datamodule_init_args",
    "trainer": "trainer_args",
}

# Model init_args that LightningConfigFactory resolves from the datamodule via its
# auto/None/0 sentinels (see _build_model). A tuned value here is either silently overwritten or
# corrupts the shape contract between the datamodule and the model, so both are worth refusing.
# NOTE: `embedding_dims` is deliberately absent - the factory never touches it, and
# resolve_embedding_dims accepts "auto" or a scalar, which makes it a genuine search dimension.
FACTORY_RESOLVED_MODEL_KEYS = frozenset(
    {
        "static_dim",
        "target_dim",
        "modality_dims",
        "temporal_steps",
        "edge_attr_dim",
        "grid_years",
        # Whether the data carries coordinates at all - a property of USE_HARMONIC_COORDS, not a
        # hyperparameter. Sweeping it would change the fusion width without changing the batch, so
        # the branch would read a tensor that is not there. `harmonic_num_frequencies`,
        # `harmonic_include_input` and `harmonic_hidden_dims` are deliberately absent: those are
        # genuine search dimensions.
        "coord_dim",
        "categorical_cardinalities",
        "categorical_vocabularies",
        "categorical_feature_names",
        "temporal_enabled",
        "output_dim",
        "target_mean",
        "target_scale",
        "target_transform",
        # Fitted on the train split by the datamodule, like target_mean/target_scale. `loss_lambda`,
        # `loss_shrinkage` and `loss_name` are deliberately absent - those are genuine search
        # dimensions; only the data-derived matrix is refused.
        "target_covariance",
    }
)

# Datamodule args that define the train/val/test split. SoilSequenceDataModule.setup fits the
# scaler, the categorical vocabulary and target_mean_/target_scale_ on the train split, so varying
# any of these changes what val_loss and val_r2 are even measuring. Pinning them in `fixed` is fine;
# searching over them is not.
#
# `val_size`/`test_size`/`seed` are inert once the shared split plan is injected - the study builds
# one plan up front and every trial resolves it - but they stay listed so a search space written
# against the old contract fails loudly rather than looking like it worked. `split_plan` is the
# live one: overriding it per trial is exactly the invalidation the other three used to cause.
SPLIT_DEFINING_DATAMODULE_KEYS = frozenset({"val_size", "test_size", "seed", "split_plan"})


def to_builtin(value: Any) -> Any:
    """A plain-Python copy of a drawn value.

    A model's settings are saved in its :term:`checkpoint`, which can only hold plain values.
        """
    if isinstance(value, (bool, np.bool_)):
        return bool(value)
    if isinstance(value, (str, bytes)) or value is None:
        return value.decode() if isinstance(value, bytes) else value
    if isinstance(value, Mapping):
        return {str(key): to_builtin(item) for key, item in value.items()}
    if isinstance(value, (list, tuple, set, np.ndarray)):
        return [to_builtin(item) for item in value]
    if isinstance(value, (int, np.integer)):
        return int(value)
    if isinstance(value, (float, np.floating)):
        return float(value)
    if hasattr(value, "item"):  # any remaining 0-d numpy/torch scalar
        return to_builtin(value.item())
    return value


def split_dotted(dotted: str) -> tuple[str, str]:
    """Split a setting's path into its section and its name.

    Examples
    --------
    >>> split_dotted("model.learning_rate")
    ('model', 'learning_rate')
        """
    prefix, _, remainder = dotted.partition(".")
    if not remainder:
        raise ValueError(
            f"Override key {dotted!r} needs a section prefix, e.g. 'model.learning_rate' or "
            f"'datamodule.batch_size'."
        )
    if prefix == "callbacks":
        group, _, key = remainder.partition(".")
        if not key or "." in key:
            raise ValueError(
                f"Override key {dotted!r} must be 'callbacks.<group>.<key>', e.g. "
                f"'callbacks.early_stopping.patience'."
            )
        return prefix, remainder
    if prefix not in PREFIX_SECTIONS:
        allowed = ", ".join(sorted([*PREFIX_SECTIONS, "callbacks"]))
        raise ValueError(f"Unknown override prefix {prefix!r} in {dotted!r}; expected one of: {allowed}.")
    if "." in remainder:
        raise ValueError(f"Override key {dotted!r} has too many dots for a '{prefix}' override.")
    return prefix, remainder


def validate_override_keys(dotted_keys: Iterable[str], *, searched: bool) -> None:
    """Refuse settings that must not be searched, naming every one of them.

    Some settings would change what the trials are being compared on - the split, the targets - so a
    search that touched them would not be measuring what it claims.
        """
    problems: list[str] = []
    for dotted in dotted_keys:
        prefix, key = split_dotted(dotted)
        if prefix == "model" and key in FACTORY_RESOLVED_MODEL_KEYS:
            problems.append(
                f"  {dotted}: resolved from the datamodule by LightningConfigFactory._build_model; "
                f"overriding it breaks the model/datamodule shape contract."
            )
        elif prefix == "datamodule" and key == "split_plan":
            problems.append(
                f"  {dotted}: the split is decided once for the whole run, in main_config.yml's "
                f"`split:` block, and shared with the sklearn family. A per-trial plan would make "
                f"the trials incomparable with each other and with the leaderboard."
            )
        elif searched and prefix == "datamodule" and key in SPLIT_DEFINING_DATAMODULE_KEYS:
            problems.append(
                f"  {dotted}: changes the train/val/test split, and with it the fitted scaler, the "
                f"categorical vocabulary and target_mean_/target_scale_. Trials would not be "
                f"comparable. Set it in main_config.yml's `split:` block, which applies to the "
                f"whole study, rather than searching it."
            )
    if problems:
        section = "params" if searched else "fixed"
        raise ValueError(f"Invalid keys in the '{section}' block of the search space:\n" + "\n".join(problems))


def apply_overrides(spec: dict[str, Any], overrides: Mapping[str, Any]) -> dict[str, Any]:
    """Write the drawn settings into a copied model-list entry, and return it."""
    for dotted, value in overrides.items():
        prefix, remainder = split_dotted(dotted)
        if prefix == "callbacks":
            group, _, key = remainder.partition(".")
            destination = spec.setdefault("callbacks", {}).setdefault(group, {})
        else:
            destination, key = spec.setdefault(PREFIX_SECTIONS[prefix], {}), remainder
        destination[key] = to_builtin(value)
    return spec
