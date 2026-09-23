"""Write a winning :term:`trial` back out as a model-list file you can train from.

The file is built by writing the winning settings into the model-list entry through exactly the
code a trial used, so what it holds is provably the configuration that produced the score rather
than a reconstruction of it.
"""

from __future__ import annotations

import datetime
from copy import deepcopy
from pathlib import Path
from typing import Any

import optuna
import yaml

from yg_eo_soilnet.hpo.overrides import apply_overrides
from yg_eo_soilnet.hpo.search_space import Objective

OVERRIDES_ATTR = "overrides"

# Dataloader throughput knobs, not hyperparameters: they change how fast batches arrive and nothing
# else. datamodules/loaders.build_loader is what makes that true. Before it, persistent_workers
# changed the global RNG stream from epoch 1 onward, so a retrain could not reproduce its trial.
# A study pins them to values that suit hundreds of short trials, and
# without this the exported production config would silently inherit those instead of the
# registry's - which is how `num_workers: 4` and `persistent_workers: true` ended up in a tuned file
# whose registry said 11 and false.
INFRASTRUCTURE_DATAMODULE_KEYS = ("num_workers", "pin_memory", "persistent_workers")


def best_overrides(study: optuna.Study) -> dict[str, Any]:
    """The settings the best trial actually ran with.

    Read back from the trial rather than drawn again: a conditional setting cannot be reproduced
    outside a live trial.
    """
    trial = study.best_trial
    overrides = trial.user_attrs.get(OVERRIDES_ATTR)
    if overrides is None:
        raise KeyError(
            f"Best trial {trial.number} of study {study.study_name!r} carries no {OVERRIDES_ATTR!r} "
            f"attribute. It predates this exporter, or was not run by TrialObjective."
        )
    return dict(overrides)


def build_tuned_spec(registry_entry: dict[str, Any], overrides: dict[str, Any], objective: Objective) -> dict[str, Any]:
    """The original model-list entry with the winning settings written in, ready to train."""
    spec = apply_overrides(deepcopy(registry_entry), overrides)
    spec["enabled"] = True
    spec.setdefault("trainer_args", {})["enable_checkpointing"] = True

    # The study early-stopped and scored on the objective metric. If the production run reverted to
    # the registry's val_loss it would select a different epoch than the one the trial was ranked
    # on, and the retrained model would not reproduce the study's number.
    callbacks = spec.setdefault("callbacks", {})
    for group in ("early_stopping", "checkpoint"):
        callbacks.setdefault(group, {}).update(monitor=objective.metric, mode=objective.mode)

    # Throughput settings come back from the registry, not from whatever the trial ran with. A key
    # the registry does not declare is removed rather than kept, so the entry falls back to the
    # factory's config.LIGHTNING_* default exactly as the registry itself would.
    source_datamodule_args = registry_entry.get("datamodule_init_args", {}) or {}
    datamodule_args = spec.setdefault("datamodule_init_args", {})
    for key in INFRASTRUCTURE_DATAMODULE_KEYS:
        if key in source_datamodule_args:
            datamodule_args[key] = deepcopy(source_datamodule_args[key])
        else:
            datamodule_args.pop(key, None)
    return spec


def _header(
    study: optuna.Study,
    entry: str,
    objective: Objective,
    registry_path: str | None,
    path: Path,
    *,
    trial_number: int | None = None,
    headline_value: float | None = None,
    rerank: Any = None,
) -> str:
    """The comment block at the top of an exported file: which study, which trial, what it scored."""
    number = study.best_trial.number if trial_number is None else trial_number
    value = study.best_value if headline_value is None else headline_value
    lines = [
        "# Tuned Lightning registry entry, exported from an Optuna study.",
        "#",
        f"#   study      : {study.study_name}",
        f"#   entry      : {entry}",
        f"#   trial      : #{number} of {len(study.trials)}",
        f"#   objective  : {objective.metric} = {value:.6f} ({objective.direction})",
    ]
    if rerank is None:
        lines += [
            "#",
            "# NOTE: that value is the best of many trials, each itself the best epoch of a noisy",
            "# run - a maximum over noise, so it is optimistically biased and a retrain will",
            "# typically fall short of it. `tune.py --rerank-top K` re-runs the shortlist over",
            "# several seeds and reports what a retrain should actually deliver.",
        ]
    else:
        lines += [
            f"#   reranked   : {objective.metric} = {rerank.mean:.6f} +- {rerank.std:.6f} "
            f"over {len(rerank.values)} seed(s)  <- expect this on a retrain",
            "#   selection  : chosen on the re-ranked mean, not on the headline value",
        ]
        if rerank.reproduced is False:
            lines.append(
                f"#   WARNING    : the re-run at the trial's own seed gave {rerank.values[0]:.6f}, "
                f"which does not reproduce the trial."
            )
    lines.append(f"#   exported   : {datetime.datetime.now().isoformat(timespec='seconds')}")
    if registry_path:
        lines.append(f"#   source     : {registry_path}")
    lines += [
        "#",
        f"# Compare against the MLflow `{objective.metric}` of the retrained run. NOT r2_score or",
        "# r2_test - those are TEST-split R2 in original units after expm1, a different split, a",
        "# different metric and a different space from anything the study optimized.",
        "#",
        "# Values pinned under `fixed:` in the search space are baked in here too - notably",
        "# trainer.max_epochs, which is the tuning budget. Raise it for a final production run if you",
        "# want early stopping, rather than the epoch budget, to decide when to stop.",
        "#",
        f"# Exceptions: {', '.join(INFRASTRUCTURE_DATAMODULE_KEYS)} are restored from the source",
        "# registry. They are throughput knobs that change no result, so production keeps its own.",
        "#",
        "# Train it with:",
        f"#   LIGHTNING_MODEL_REGISTRY_PATH={path} python main.py",
        "",
    ]
    return "\n".join(lines)


def export_best_config(
    study: optuna.Study,
    entry: str,
    registry_entry: dict[str, Any],
    objective: Objective,
    path: str | Path,
    *,
    registry_path: str | None = None,
    rerank: Any = None,
) -> Path:
    """Write the winner to a model-list file and return what was written.

    Parameters
    ----------
    study : optuna.Study
        The finished study.
    context : ObjectiveContext
        The shared context the trials ran in.
    path : str
        Where to write the file.
    rerank : RerankResult, optional
        The :term:`reranked <rerank>` winner, exported in place of the study's headline best.

    Returns
    -------
    dict
        ``{model name: its settings}``, as written.
    """
    if rerank is None:
        overrides, trial_number, headline = best_overrides(study), None, None
    else:
        overrides = dict(rerank.overrides)
        trial_number, headline = rerank.trial_number, rerank.original_value
    spec = build_tuned_spec(registry_entry, overrides, objective)

    path = Path(path)
    path.parent.mkdir(parents=True, exist_ok=True)
    with path.open("w") as handle:
        handle.write(
            _header(
                study,
                entry,
                objective,
                registry_path,
                path,
                trial_number=trial_number,
                headline_value=headline,
                rerank=rerank,
            )
        )
        yaml.safe_dump({entry: spec}, handle, sort_keys=False, default_flow_style=False)
    return path
