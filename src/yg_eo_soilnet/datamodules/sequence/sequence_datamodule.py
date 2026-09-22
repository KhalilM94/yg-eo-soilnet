"""Serve the deep-learning model its batches, and learn the scaling that prepares them."""

from __future__ import annotations

from copy import deepcopy
from typing import Any, Mapping, Optional

import numpy as np
import pandas as pd
import torch
from torch.utils.data import Dataset

from lightning.pytorch import LightningDataModule

from yg_eo_soilnet.datamodules.categorical import CategoricalEncoder
from yg_eo_soilnet.datamodules.loaders import build_loader
from yg_eo_soilnet.datamodules.sequence.sequence_bundle import SoilSequenceBundle
from yg_eo_soilnet.datamodules.splitting import SplitPlan
from yg_eo_soilnet.targets import select_target_columns


class _PointDataset(Dataset):
    """Hands out point numbers; the batch itself is assembled by ``_collate_points``."""

    def __init__(self, point_indices: np.ndarray):
        self.point_indices = np.asarray(point_indices, dtype=np.int64)

    def __len__(self) -> int:
        return int(self.point_indices.size)

    def __getitem__(self, index: int) -> int:
        return int(self.point_indices[index])


class SoilSequenceDataModule(LightningDataModule):
    """Serve `soil_cnn` its batches: covariates, categories, lab values and dated readings.

    It learns everything needed to prepare the inputs - the standardization statistics, the fill
    values for gaps, the category numbering, the area the coordinates cover - **from the training
    points only**, so nothing about the held-out points reaches the model. :meth:`setup` fits them;
    :meth:`preprocessing_state` hands them to the checkpoint, so a saved model can prepare raw data
    on its own, and :meth:`apply_preprocessing_state` installs them again when it is served.

    Points keep different numbers of readings. Each batch is padded to its own longest series and
    carries a mask, so nothing assumes a fixed number of readings.

    Parameters
    ----------
    sequence_bundle : SoilSequenceBundle or mapping
        Everything known about every point; see
        :class:`~yg_eo_soilnet.datamodules.sequence.sequence_bundle.SoilSequenceBundle`.
    batch_size : int, default 32
        Points per batch.
    val_size, test_size : float, default 0.2
        Only used without a ``split_plan``, for standalone use and tests.
    num_workers : int, default 0
        Background processes preparing batches.
    pin_memory : bool, default False
        Speeds up copying batches to a GPU.
    persistent_workers : bool, default False
        Keep the worker processes alive between epochs.
    seed : int, default 42
        Seed for the fallback split.
    shuffle : bool, default False
        Draw the training points in a new order each epoch.
    target_transform : {None, "log1p"}, optional
        Train on 10·ln(1 + *y*) instead of *y*.
    max_sequence_length : int, optional
        Keep at most this many readings per point, the most recent ones.
    split_plan : SplitPlan, optional
        The run's shared split. Given, it decides the three sets and ``val_size``/``test_size`` are
        ignored.
    active_targets : list of str, optional
        The targets this model predicts; all of the bundle's targets unless given.

    Raises
    ------
    ValueError
        If ``target_transform`` is neither ``None`` nor ``"log1p"``.
    """

    def __init__(
        self,
        sequence_bundle: "SoilSequenceBundle | Mapping[str, Any]",
        batch_size: int = 32,
        val_size: float = 0.2,
        test_size: float = 0.2,
        num_workers: int = 0,
        pin_memory: bool = False,
        persistent_workers: bool = False,
        seed: int = 42,
        shuffle: bool = False,
        target_transform: Optional[str] = None,
        max_sequence_length: Optional[int] = None,
        split_plan: Optional["SplitPlan"] = None,
        active_targets: Optional[list[str]] = None,
    ):
        super().__init__()
        self.sequence_bundle = deepcopy(SoilSequenceBundle.from_mapping(sequence_bundle))
        # Narrowed once, here: every width, statistic and frame below then follows from it, so
        # nothing further down needs a one-target branch of its own.
        self.active_targets = list(active_targets) if active_targets else None
        narrowed, target_names, _ = select_target_columns(
            self.sequence_bundle.targets, self.sequence_bundle.target_names, self.active_targets
        )
        self.sequence_bundle.targets = narrowed
        self.sequence_bundle.target_names = target_names
        self.target_transform = None if target_transform is None else str(target_transform).lower()
        if self.target_transform not in {None, "none", "log1p"}:
            raise ValueError("target_transform must be None or 'log1p'")
        if self.target_transform == "none":
            self.target_transform = None

        self.batch_size = batch_size
        self.val_size = val_size
        self.test_size = test_size
        # The run's shared split. Without one, the fractions below are used instead - which
        # standalone and test use rely on.
        self.split_plan = split_plan
        self.num_workers = num_workers
        self.pin_memory = pin_memory
        self.persistent_workers = persistent_workers and num_workers > 0
        self.seed = seed
        self.shuffle = shuffle
        self.max_sequence_length = None if max_sequence_length is None else max(1, int(max_sequence_length))

        self._is_setup = False
        self.train_idx_: Optional[np.ndarray] = None
        self.val_idx_: Optional[np.ndarray] = None
        self.test_idx_: Optional[np.ndarray] = None
        self.X_train_frame_ = None
        self.y_train_frame_ = None
        self.X_val_frame_ = None
        self.y_val_frame_ = None
        self.X_test_frame_ = None
        self.y_test_frame_ = None

        # Fitted on the training points only, in setup().
        self.static_mean_: Optional[np.ndarray] = None
        self.static_scale_: Optional[np.ndarray] = None
        # What a missing covariate is filled with. The median, not the mean: a skewed column's
        # mean sits where no sample actually is.
        self.static_median_: Optional[np.ndarray] = None
        # The category numbering, also from the training points only: a label seen only in
        # validation or test must reach the model as unknown, exactly as a new label would later.
        self.categorical_encoder_: Optional[CategoricalEncoder] = None
        self.categorical_codes_: Optional[np.ndarray] = None
        self.sequence_mean_: dict[str, np.ndarray] = {}
        self.sequence_scale_: dict[str, np.ndarray] = {}
        self.target_mean_: Optional[np.ndarray] = None
        self.target_scale_: Optional[np.ndarray] = None
        # How the training targets vary together, in the same units the loss works in. Fitted here
        # because this is the only place holding every training point at once.
        self.target_covariance_: Optional[np.ndarray] = None
        # The same three statistics for the lab values carried as auxiliary inputs.
        self.label_mean_: Optional[np.ndarray] = None
        self.label_scale_: Optional[np.ndarray] = None
        self.label_median_: Optional[np.ndarray] = None
        # The area the training points cover, which is what the coordinates are measured against.
        # Saved with the model: a served request can be one point, whose own extent is nothing.
        self.coord_min_: Optional[np.ndarray] = None
        self.coord_max_: Optional[np.ndarray] = None

        # The input widths the model is built from. The measured-or-filled flags widen the
        # covariate block, so static_dim counts them: the model must match what a batch carries.
        self.static_validity_names = list(self.sequence_bundle.static_validity_names)
        self.static_dim = int(
            np.asarray(self.sequence_bundle.static_features).shape[1] + len(self.static_validity_names)
        )
        self.target_dim = int(np.asarray(self.sequence_bundle.targets).shape[1])
        self.static_feature_names = list(self.sequence_bundle.static_feature_names)
        # Which of those covariates are the spatial-context group. Descriptive only: they are
        # ordinary inputs, and this just lets the SHAP figures report them together.
        self.context_feature_names = list(self.sequence_bundle.context_feature_names)
        # 2 when the model reads coordinates, 0 otherwise - and 0 leaves it without a coordinate
        # branch at all.
        self.coord_dim = int(self.sequence_bundle.coord_dim)
        self.coord_names = list(self.sequence_bundle.coord_names)
        # The category columns are known now; how many codes each has is not, since that depends
        # on the training points. setup() fills those in before the model is built.
        self.categorical_feature_names = list(self.sequence_bundle.categorical_feature_names)
        self.categorical_cardinalities: list[int] = []
        self.categorical_vocabularies: list[list[str]] = []
        self.target_names = list(self.sequence_bundle.target_names)
        # Every lab column on offer; a model picks the ones it named as auxiliary inputs. One
        # datamodule serves several models, so nothing is selected here.
        self.label_feature_names = list(self.sequence_bundle.label_feature_names)
        self.label_dim = int(self.sequence_bundle.label_dim)
        self.modality_dims = dict(self.sequence_bundle.modality_dims)
        self.temporal_enabled = bool(self.sequence_bundle.temporal_enabled and self.modality_dims)
        self.grid_years = self._infer_grid_years()

    def preprocessing_state(self) -> dict:
        """Everything a saved model needs to prepare raw data by itself.

        The statistics, fill values, category numbering, column names and the area the coordinates
        were measured against - all fitted on the training points in :meth:`setup`. They go into the
        :term:`checkpoint`, which is what makes a saved model usable on new points.

        Returns
        -------
        dict
            Plain lists, numbers and strings only, so the checkpoint can be read back safely.
        """

        def as_list(values) -> list[float]:
            """A statistic as a flat list of plain numbers, so a checkpoint can hold it."""
            if values is None:
                return []
            return [float(value) for value in np.asarray(values, dtype=np.float64).reshape(-1)]

        return {
            "static_mean": as_list(self.static_mean_),
            "static_scale": as_list(self.static_scale_),
            "static_median": as_list(self.static_median_),
            "static_feature_names": list(self.static_feature_names),
            # Which covariates carry a flag, and so how wide the covariate block is. A served
            # model must keep that width, whatever the new points happen to be missing.
            "static_validity_names": list(self.static_validity_names),
            # Carried so a restored model labels its attributions as the training run did.
            "context_feature_names": list(self.context_feature_names),
            # Without this a new point cannot be placed on the same scale the model was trained
            # on. Empty when coordinates are switched off.
            "coord_min": as_list(self.coord_min_),
            "coord_max": as_list(self.coord_max_),
            "coord_names": list(self.coord_names),
            "sequence_mean": {name: as_list(values) for name, values in self.sequence_mean_.items()},
            "sequence_scale": {name: as_list(values) for name, values in self.sequence_scale_.items()},
            "modality_column_names": {
                name: list(columns) for name, columns in self.sequence_bundle.modality_columns.items()
            },
            "label_mean": as_list(self.label_mean_),
            "label_scale": as_list(self.label_scale_),
            "label_median": as_list(self.label_median_),
            "label_feature_names": list(self.label_feature_names),
            "categorical_feature_names": list(self.categorical_feature_names),
            "categorical_vocabularies": [
                [str(category) for category in vocabulary] for vocabulary in self.categorical_vocabularies
            ],
            "target_mean": as_list(self.target_mean_),
            "target_scale": as_list(self.target_scale_),
            "target_names": list(self.target_names),
        }

    def apply_preprocessing_state(self, state: Mapping[str, Any]) -> None:
        """Install the statistics a model was trained with, instead of fitting new ones.

        The counterpart of :meth:`setup`, used when a saved model predicts new points: those points
        are not a training set - there may be one of them - so fitting statistics on them would
        measure each request against itself and make a prediction depend on what else was in the
        batch. A category the new points have and training did not lands on the reserved code.

        Parameters
        ----------
        state : mapping
            What :meth:`preprocessing_state` returned.

        Raises
        ------
        ValueError
            If ``state`` is empty.
        """
        if not state:
            raise ValueError("apply_preprocessing_state needs the state produced by preprocessing_state()")

        def as_array(values, dtype=np.float32):
            """A saved statistic back as an array, or None when it holds nothing."""
            array = np.asarray(list(values or []), dtype=dtype)
            return None if array.size == 0 else array

        self.static_mean_ = as_array(state.get("static_mean"))
        self.static_scale_ = as_array(state.get("static_scale"))
        self.static_median_ = as_array(state.get("static_median"))
        # Restored rather than worked out again, so the covariate block keeps the width the model
        # was trained with.
        if "static_validity_names" in state:
            self.static_validity_names = [str(name) for name in (state.get("static_validity_names") or [])]
        if "context_feature_names" in state:
            self.context_feature_names = [str(name) for name in (state.get("context_feature_names") or [])]
        # A point outside the training area lands outside the trained range, and is not clipped:
        # that is correct, and the model handles it.
        self.coord_min_ = as_array(state.get("coord_min"), dtype=np.float64)
        self.coord_max_ = as_array(state.get("coord_max"), dtype=np.float64)
        if "coord_names" in state:
            self.coord_names = [str(name) for name in (state.get("coord_names") or [])]
        self.target_mean_ = as_array(state.get("target_mean"))
        self.target_scale_ = as_array(state.get("target_scale"))
        self.label_mean_ = as_array(state.get("label_mean"))
        self.label_scale_ = as_array(state.get("label_scale"))
        self.label_median_ = as_array(state.get("label_median"))
        self.sequence_mean_ = {
            name: np.asarray(values, dtype=np.float32)
            for name, values in (state.get("sequence_mean") or {}).items()
        }
        self.sequence_scale_ = {
            name: np.asarray(values, dtype=np.float32)
            for name, values in (state.get("sequence_scale") or {}).items()
        }

        vocabularies = state.get("categorical_vocabularies") or []
        names = state.get("categorical_feature_names") or []
        raw_categoricals = np.asarray(self.sequence_bundle.static_categoricals, dtype=object)
        if vocabularies and names and raw_categoricals.size:
            self.categorical_encoder_ = CategoricalEncoder.from_vocabularies(names, vocabularies)
            self.categorical_codes_ = self.categorical_encoder_.transform(raw_categoricals)
            self.categorical_vocabularies = [list(vocabulary) for vocabulary in vocabularies]
            self.categorical_cardinalities = [len(vocabulary) + 1 for vocabulary in vocabularies]
        else:
            self.categorical_encoder_ = None
            self.categorical_codes_ = np.zeros((raw_categoricals.shape[0], 0), dtype=np.int64)

        self._is_setup = True

    def collate(self, point_indices) -> dict[str, Any]:
        """Build one batch from these point numbers.

        Parameters
        ----------
        point_indices : sequence of int
            Positions in the bundle.

        Returns
        -------
        dict
            Tensors ready for the model.
        """
        return self._collate_points(point_indices)

    def _infer_grid_years(self) -> int:
        """How many years the :term:`calendar grid` needs, from the longest single point history.

        Read from the data, so one year of readings gives a one-row grid and ten years give ten.
        Measured per point, because each point's grid is counted back from its own latest reading.
        """
        longest = 0
        has_observations = False
        for per_point_times in (self.sequence_bundle.sequence_times or {}).values():
            for times in per_point_times:
                times = np.asarray(times)
                if not times.size:
                    continue
                has_observations = True
                # Counted in calendar years: readings from December 2017 to February 2018 are two
                # months apart but occupy two rows of the grid.
                longest = max(longest, int(np.floor(times[-1])) - int(np.floor(times[0])) + 1)
        if not has_observations:
            return 0
        return max(1, longest)

    # --- lifecycle ---------------------------------------------------------

    def setup(self, stage: Optional[str] = None) -> None:
        """Split the points and fit every statistic on the training ones. Runs once.

        Parameters
        ----------
        stage : str, optional
            Lightning's stage name; the same work is done whatever it is.
        """
        if self._is_setup:
            return

        train_idx, val_idx, test_idx = self._split_indices(self.sequence_bundle.num_points)
        self._fit_normalization(train_idx)
        self._fit_categoricals(train_idx)
        self.train_idx_, self.val_idx_, self.test_idx_ = train_idx, val_idx, test_idx
        self._is_setup = True

        self.X_train_frame_, self.y_train_frame_ = self._build_split_frames(train_idx)
        self.X_val_frame_, self.y_val_frame_ = self._build_split_frames(val_idx)
        self.X_test_frame_, self.y_test_frame_ = self._build_split_frames(test_idx)

    def train_dataloader(self):
        """The training batches, shuffled if asked for."""
        if not self._is_setup:
            self.setup("fit")
        # Only training drops a short last batch: a batch of one point cannot be normalized, and a
        # handful of points makes a noisy update. Scoring must keep every point.
        drop_last = self.train_idx_ is not None and self.train_idx_.size > max(1, int(self.batch_size))
        return self._make_loader(self.train_idx_, shuffle=self.shuffle, drop_last=drop_last)

    def val_dataloader(self):
        """The validation batches, watched during training."""
        if not self._is_setup:
            self.setup("fit")
        return self._make_loader(self.val_idx_)

    def test_dataloader(self):
        """The test batches, used once training has finished."""
        if not self._is_setup:
            self.setup("test")
        return self._make_loader(self.test_idx_)

    def predict_dataloader(self):
        """The test batches again, in a fixed order, for collecting predictions."""
        if not self._is_setup:
            self.setup("predict")
        # Never shuffled: predictions are matched to the measured values by position.
        return self._make_loader(self.test_idx_)

    def _make_loader(self, point_indices, *, shuffle: bool = False, drop_last: bool = False):
        """Build a DataLoader over these points."""
        point_indices = np.asarray(point_indices, dtype=np.int64)
        batch_size = max(1, int(self.batch_size)) if point_indices.size else 1
        # build_loader, not a bare DataLoader: the loading settings must not change what the run
        # trains to. See yg_eo_soilnet.datamodules.loaders.
        return build_loader(
            _PointDataset(point_indices),
            batch_size=batch_size,
            drop_last=bool(drop_last),
            shuffle=bool(shuffle) and point_indices.size > 1,
            num_workers=self.num_workers,
            pin_memory=self.pin_memory,
            persistent_workers=self.persistent_workers,
            collate_fn=self._collate_points,
        )

    # --- standardization (fitted on the train split only) ------------------

    @staticmethod
    def _finite(array: np.ndarray) -> np.ndarray:
        """Replace missing and infinite values with 0, so one bad cell cannot spoil a statistic."""
        return np.nan_to_num(np.asarray(array, dtype=np.float64), nan=0.0, posinf=0.0, neginf=0.0)

    @staticmethod
    def _safe_scale(scale: np.ndarray) -> np.ndarray:
        """Return standard deviations, with 1 where a column does not vary (never divide by 0)."""
        scale = np.asarray(scale, dtype=np.float32)
        scale[~np.isfinite(scale) | (scale < 1e-8)] = 1.0
        return scale

    def _fit_normalization(self, train_idx: np.ndarray) -> None:
        """Fit every statistic - covariates, targets, lab values, readings - on the training points."""
        indices = np.asarray(train_idx, dtype=np.int64)
        if indices.size == 0:
            return

        coords = np.asarray(self.sequence_bundle.coords)
        if coords.size and coords.shape[1]:
            train_coords = np.asarray(coords[indices], dtype=np.float64)
            self.coord_min_ = train_coords.min(axis=0)
            self.coord_max_ = train_coords.max(axis=0)

        static_features = np.asarray(self.sequence_bundle.static_features)
        if static_features.size:
            # Gaps are filled with the training median, so a gap costs one value rather than the
            # whole soil sample. The statistics are measured after the fill, so a filled cell lands
            # where the model expects it.
            train_static = np.asarray(static_features[indices], dtype=np.float64)
            measured = np.isfinite(train_static)
            counts = measured.sum(axis=0)
            median = np.zeros(train_static.shape[1], dtype=np.float64)
            for column in range(train_static.shape[1]):
                if counts[column]:
                    median[column] = np.median(train_static[measured[:, column], column])
            filled = np.where(measured, train_static, median)
            self.static_median_ = median.astype(np.float32)
            self.static_mean_ = filled.mean(axis=0).astype(np.float32)
            self.static_scale_ = self._safe_scale(filled.std(axis=0))

        targets = np.asarray(self.sequence_bundle.targets)
        if targets.size:
            # Measured after the log transform, so the two undo in the right order.
            train_targets = self._apply_target_transform(self._finite(targets[indices]))
            self.target_mean_ = train_targets.mean(axis=0).astype(np.float32)
            self.target_scale_ = self._safe_scale(train_targets.std(axis=0))
            # In the units the loss works in, so a loss can use it as it stands. Standardized
            # first, so this is the correlation matrix.
            if indices.size > 1 and train_targets.shape[1] > 1:
                standardized = (train_targets - self.target_mean_) / self.target_scale_
                self.target_covariance_ = np.atleast_2d(
                    np.cov(standardized, rowvar=False, ddof=0)
                ).astype(np.float64)

        label_features = np.asarray(self.sequence_bundle.label_features)
        if label_features.size:
            # Measured values only: counting the fill value into the statistics it came from would
            # shrink the spread and stretch every real reading.
            train_labels = np.asarray(label_features[indices], dtype=np.float64)
            measured = np.isfinite(train_labels)
            counts = measured.sum(axis=0)
            # A column measured on no training point becomes a constant the model can only
            # ignore - the honest answer, rather than an invented centre.
            median = np.zeros(train_labels.shape[1], dtype=np.float64)
            for column in range(train_labels.shape[1]):
                if counts[column]:
                    median[column] = np.median(train_labels[measured[:, column], column])
            # Measured after the fill, so a filled cell lands where the model expects it.
            filled = np.where(measured, train_labels, median)
            self.label_median_ = median.astype(np.float32)
            self.label_mean_ = filled.mean(axis=0).astype(np.float32)
            self.label_scale_ = self._safe_scale(filled.std(axis=0))

        # One statistic per channel per data source, over the training points' real readings.
        for modality_name, per_point_values in (self.sequence_bundle.sequences or {}).items():
            channels = len(self.sequence_bundle.modality_columns.get(modality_name, []))
            selected = [
                index for index in indices if index < len(per_point_values) and len(per_point_values[index])
            ]
            if not selected:
                self.sequence_mean_[modality_name] = np.zeros(channels, dtype=np.float32)
                self.sequence_scale_[modality_name] = np.ones(channels, dtype=np.float32)
                continue

            stacked = self._finite(np.concatenate([per_point_values[index] for index in selected], axis=0))
            valid = np.concatenate(
                [self.sequence_bundle.validity_for(modality_name, index) for index in selected], axis=0
            )
            # Measured readings only: filled ones are all the same value, and counting them would
            # pull the mean towards it and shrink the spread.
            counts = valid.sum(axis=0)
            mean = np.where(counts > 0, (stacked * valid).sum(axis=0) / np.maximum(counts, 1), 0.0)
            variance = np.where(
                counts > 1,
                (((stacked - mean) ** 2) * valid).sum(axis=0) / np.maximum(counts - 1, 1),
                0.0,
            )
            self.sequence_mean_[modality_name] = mean.astype(np.float32)
            self.sequence_scale_[modality_name] = self._safe_scale(np.sqrt(variance))

    def _fit_categoricals(self, train_idx: np.ndarray) -> None:
        """Number the category labels from the training points, then code every point with it.

        A label appearing only in validation or test is not in the numbering, so it gets the
        reserved code - exactly as a new label would when the model is used later.
        """
        raw = np.asarray(self.sequence_bundle.static_categoricals, dtype=object)
        names = self.categorical_feature_names
        if raw.ndim != 2 or raw.shape[1] == 0 or not names:
            self.categorical_encoder_ = None
            self.categorical_codes_ = np.zeros((raw.shape[0] if raw.ndim == 2 else 0, 0), dtype=np.int64)
            self.categorical_cardinalities = []
            self.categorical_vocabularies = []
            return

        indices = np.asarray(train_idx, dtype=np.int64)
        # With no training points there is nothing to number from, and every label gets the
        # reserved code. Falling back on all the points would be looking at the held-out ones.
        fit_rows = raw[indices] if indices.size else raw[:0]

        encoder = CategoricalEncoder().fit(fit_rows, names)
        self.categorical_encoder_ = encoder
        self.categorical_codes_ = encoder.transform(raw)
        self.categorical_cardinalities = encoder.cardinalities
        self.categorical_vocabularies = encoder.vocabularies

    def _standardize_static(self, values: np.ndarray, validity: Optional[np.ndarray] = None) -> np.ndarray:
        """Standardize the covariates, filling gaps with the training median.

        The measured-or-filled flags are worked out from the raw values first - afterwards a filled
        cell looks like a measured one - and appended, so the model can tell them apart.
        """
        if values.size == 0:
            return np.asarray(values, dtype=np.float32)

        raw = np.asarray(values, dtype=np.float64)
        measured = np.isfinite(raw)
        filled = raw if self.static_median_ is None else np.where(measured, raw, self.static_median_)

        if self.static_mean_ is None:
            standardized = self._finite(filled).astype(np.float32)
        else:
            standardized = ((self._finite(filled) - self.static_mean_) / self.static_scale_).astype(np.float32)

        flags = self._static_validity_channels(measured, validity)
        if flags.size:
            standardized = np.concatenate([standardized, flags], axis=1)
        return standardized

    def _static_validity_channels(
        self, measured: np.ndarray, validity: Optional[np.ndarray]
    ) -> np.ndarray:
        """The measured-or-filled flags, for the covariates that have gaps."""
        if not self.static_validity_names:
            return np.empty((measured.shape[0], 0), dtype=np.float32)
        if validity is not None and np.asarray(validity).size:
            return np.asarray(validity, dtype=np.float32).reshape(measured.shape[0], -1)
        # No flags supplied - raw rows, as at serving time - so read them off the values, taking
        # the same columns in the same order.
        positions = [self.static_feature_names.index(name) for name in self.static_validity_names]
        return measured[:, positions].astype(np.float32)

    def _normalize_coords(self, values: np.ndarray) -> np.ndarray:
        """Place the coordinates on the -1 to 1 range the model's location branch works on.

        Measured against the area the training points cover, so the scale means the same thing
        whatever the dataset. A point outside that area lands outside the range and is left there:
        clipping would make a distant location look like one just beyond the edge.
        """
        values = np.asarray(values, dtype=np.float64)
        if values.size == 0 or self.coord_min_ is None or self.coord_max_ is None:
            return values.astype(np.float32)

        span = np.asarray(self.coord_max_, dtype=np.float64) - np.asarray(self.coord_min_, dtype=np.float64)
        # An axis with no extent - every training point on one line, or only one point - carries
        # no location information, so it becomes a constant rather than a division by zero.
        safe_span = np.where(np.isfinite(span) & (np.abs(span) > 1e-12), span, 1.0)
        normalized = 2.0 * (values - self.coord_min_) / safe_span - 1.0
        normalized = np.where(np.abs(span) > 1e-12, normalized, 0.0)
        return normalized.astype(np.float32)

    def _standardize_labels(self, values: np.ndarray) -> tuple[np.ndarray, np.ndarray]:
        """Standardize the lab values, filling gaps with the training median.

        Returns
        -------
        standardized : numpy.ndarray
        validity : numpy.ndarray of bool
            True where the value was measured. Recorded before the fill, after which the two would
            be indistinguishable.
        """
        values = np.asarray(values, dtype=np.float64)
        validity = np.isfinite(values)
        if values.size == 0 or self.label_median_ is None:
            return np.nan_to_num(values, nan=0.0, posinf=0.0, neginf=0.0).astype(np.float32), validity

        filled = np.where(validity, values, self.label_median_)
        return ((filled - self.label_mean_) / self.label_scale_).astype(np.float32), validity

    def _apply_target_transform(self, values: np.ndarray) -> np.ndarray:
        """Apply the log transform to the targets, matching the scikit-learn side (10·ln(1 + y))."""
        if self.target_transform != "log1p" or values.size == 0:
            return values

        if np.any(values < 0):
            import warnings

            warnings.warn(
                f"target_transform='log1p' clipped {int((values < 0).sum())} negative target value(s) "
                "to 0; log1p is undefined below -1 and these targets are expected to be non-negative.",
                RuntimeWarning,
                stacklevel=2,
            )
            values = np.maximum(values, 0.0)
        return 10.0 * np.log1p(values)

    def _standardize_targets(self, values: np.ndarray) -> np.ndarray:
        """Transform and standardize the targets, into the units the model is trained in."""
        transformed = self._apply_target_transform(self._finite(values))
        if self.target_mean_ is None or values.size == 0:
            return transformed.astype(np.float32)
        return ((transformed - self.target_mean_) / self.target_scale_).astype(np.float32)

    def _standardize_sequence(self, modality_name: str, values: np.ndarray) -> np.ndarray:
        """Standardize one data source's readings, channel by channel."""
        mean = self.sequence_mean_.get(modality_name)
        if mean is None or values.size == 0:
            return self._finite(values).astype(np.float32)
        return ((self._finite(values) - mean) / self.sequence_scale_[modality_name]).astype(np.float32)

    # --- batch assembly ----------------------------------------------------

    def _collate_points(self, point_indices) -> dict[str, Any]:
        """Assemble one batch: prepare every input and pad the readings to this batch's longest."""
        indices = np.asarray(point_indices, dtype=np.int64)
        bundle = self.sequence_bundle

        static_features = np.asarray(bundle.static_features)
        static_validity = np.asarray(bundle.static_validity)
        targets = np.asarray(bundle.targets)
        x_static = (
            self._standardize_static(
                static_features[indices],
                static_validity[indices] if static_validity.size else None,
            )
            if static_features.size
            else np.empty((indices.size, 0), dtype=np.float32)
        )
        y = self._standardize_targets(targets[indices]) if targets.size else np.empty(
            (indices.size, 0), dtype=np.float32
        )

        # Codes, never scaled: they look up a vector rather than measure anything. Always present,
        # if zero-width, so nothing downstream needs a special case.
        if self.categorical_codes_ is not None and self.categorical_codes_.shape[1]:
            x_categorical = self.categorical_codes_[indices]
        else:
            x_categorical = np.zeros((indices.size, 0), dtype=np.int64)

        # Every lab column, always in the same order: the model picks what it was built for. One
        # datamodule serves several models, so a batch must not depend on which one is training.
        label_features = np.asarray(bundle.label_features)
        if label_features.size:
            x_labels, x_label_validity = self._standardize_labels(label_features[indices])
        else:
            x_labels = np.zeros((indices.size, 0), dtype=np.float32)
            x_label_validity = np.zeros((indices.size, 0), dtype=bool)

        # Measured against the training area, never against this batch. Zero-width when
        # coordinates are switched off.
        coords = np.asarray(bundle.coords)
        if coords.size and coords.shape[1]:
            x_coords = self._normalize_coords(coords[indices])
        else:
            x_coords = np.zeros((indices.size, 0), dtype=np.float32)

        batch: dict[str, Any] = {
            "x_static": torch.as_tensor(x_static, dtype=torch.float32),
            "x_categorical": torch.as_tensor(x_categorical, dtype=torch.long),
            "x_coords": torch.as_tensor(x_coords, dtype=torch.float32),
            "x_labels": torch.as_tensor(x_labels, dtype=torch.float32),
            "x_label_validity": torch.as_tensor(x_label_validity, dtype=torch.bool),
            "y": torch.as_tensor(y, dtype=torch.float32),
            "point_ids": [bundle.point_ids[index] for index in indices.tolist()],
            "target_names": list(bundle.target_names),
            "label_feature_names": list(bundle.label_feature_names),
            "sequences": {},
            "sequence_mask": {},
            "sequence_time": {},
            "sequence_validity": {},
        }

        for modality_name, per_point_values in (bundle.sequences or {}).items():
            per_point_times = bundle.sequence_times.get(modality_name, [])
            channels = len(bundle.modality_columns.get(modality_name, []))

            selected_values = []
            selected_times = []
            selected_validity = []
            for index in indices.tolist():
                values = np.asarray(per_point_values[index], dtype=np.float32)
                # Full precision: what the model reads is the gap between two nearby dates.
                times = np.asarray(per_point_times[index], dtype=np.float64)
                validity = bundle.validity_for(modality_name, index)
                if self.max_sequence_length is not None and len(times) > self.max_sequence_length:
                    # The most recent readings: they are closest to the date the soil was sampled.
                    values = values[-self.max_sequence_length :]
                    times = times[-self.max_sequence_length :]
                    validity = validity[-self.max_sequence_length :]
                selected_values.append(values)
                selected_times.append(times)
                selected_validity.append(validity)

            # Padded to this batch's longest series, never to a fixed length. At least one step,
            # so a batch whose points have no readings still has a shape.
            max_length = max((len(times) for times in selected_times), default=0)
            max_length = max(1, max_length)

            padded = np.zeros((indices.size, max_length, channels), dtype=np.float32)
            mask = np.zeros((indices.size, max_length), dtype=bool)
            times_padded = np.zeros((indices.size, max_length), dtype=np.float64)
            validity_padded = np.zeros((indices.size, max_length, channels), dtype=bool)

            for row, (values, times, validity) in enumerate(
                zip(selected_values, selected_times, selected_validity)
            ):
                length = len(times)
                if length == 0:
                    continue
                padded[row, :length] = self._standardize_sequence(modality_name, values)
                mask[row, :length] = True
                times_padded[row, :length] = times
                validity_padded[row, :length] = validity

            batch["sequences"][modality_name] = torch.as_tensor(padded, dtype=torch.float32)
            batch["sequence_mask"][modality_name] = torch.as_tensor(mask, dtype=torch.bool)
            # Full precision, as above.
            batch["sequence_time"][modality_name] = torch.as_tensor(times_padded, dtype=torch.float64)
            batch["sequence_validity"][modality_name] = torch.as_tensor(validity_padded, dtype=torch.bool)

        return batch

    # --- splits and evaluation frames --------------------------------------

    def _build_split_frames(self, point_indices):
        """The covariates and measured targets of one split, as tables in the targets' own units."""
        indices = np.asarray(point_indices, dtype=np.int64)
        static_features = np.asarray(self.sequence_bundle.static_features)
        targets = np.asarray(self.sequence_bundle.targets)

        if self.static_feature_names and len(self.static_feature_names) == static_features.shape[1]:
            feature_columns = list(self.static_feature_names)
        else:
            feature_columns = [f"feature_{index}" for index in range(static_features.shape[1])]

        if self.target_names and len(self.target_names) == targets.shape[1]:
            target_columns = list(self.target_names)
        else:
            target_columns = [f"target_{index}" for index in range(targets.shape[1])]

        if indices.size == 0:
            return pd.DataFrame(columns=feature_columns), pd.DataFrame(columns=target_columns)

        # Untransformed: the scores are computed against these, in the target's own units.
        x_frame = pd.DataFrame(static_features[indices], columns=feature_columns)
        y_frame = pd.DataFrame(targets[indices], columns=target_columns)
        return x_frame, y_frame

    def _split_indices(self, num_rows: int):
        """Which points train, which validate and which test.

        From the run's shared split when there is one, so this family and the scikit-learn family
        hold out the same points; otherwise from ``test_size`` and ``val_size``, applied one after
        the other.
        """
        empty = np.array([], dtype=np.int64)
        indices = np.arange(num_rows, dtype=np.int64)
        if num_rows <= 1:
            return indices, empty, empty

        if self.split_plan is not None:
            return self._planned_split_indices(num_rows)

        test_idx, train_val_idx = self._carve_out(indices, self.test_size)
        if train_val_idx.size <= 1:
            return train_val_idx, empty, test_idx

        val_idx, train_idx = self._carve_out(train_val_idx, self.val_size)
        return train_idx, val_idx, test_idx

    def _planned_split_indices(self, num_rows: int):
        """Read the shared split against this bundle's own point order.

        Raises
        ------
        ValueError
            If the bundle and the plan disagree on the number of points, or the plan leaves this
            family no training points.
        """
        point_ids = list(self.sequence_bundle.point_ids)
        if len(point_ids) != num_rows:
            raise ValueError(
                f"The bundle carries {len(point_ids)} point id(s) for {num_rows} row(s); the shared "
                f"split cannot be resolved."
            )
        train_idx, val_idx, test_idx = self.split_plan.split_indices(point_ids)
        assigned = train_idx.size + val_idx.size + test_idx.size
        if assigned < num_rows:
            # Expected under population_policy: intersect - these are points another family could
            # not use, so the shared split gives them to none.
            self._log(
                f"{num_rows - assigned} of {num_rows} point(s) are outside the shared split "
                f"population and are used by no split "
                f"(population_policy={self.split_plan.population_policy})."
            )
        if train_idx.size == 0:
            raise ValueError(
                "The shared split plan left this datamodule with no training points. Check "
                "split.population_policy and the eligibility of this family's rows."
            )
        return train_idx, val_idx, test_idx

    def _log(self, message: str) -> None:
        """Write one message to the module logger; a datamodule has no logger of its own."""
        import logging

        logging.getLogger(__name__).info(message)

    def _carve_out(self, indices: np.ndarray, fraction: float):
        """Hold out ``fraction`` of these points at random, returning ``(held_out, remainder)``.

        A fraction of 0 means no holdout, which ``train_test_split`` refuses outright.
        """
        fraction = min(max(float(fraction), 0.0), 0.9)
        if fraction <= 0.0:
            return np.array([], dtype=np.int64), np.asarray(indices, dtype=np.int64)

        from sklearn.model_selection import train_test_split

        remainder, held_out = train_test_split(
            indices, test_size=fraction, random_state=self.seed, shuffle=True
        )
        return np.asarray(held_out, dtype=np.int64), np.asarray(remainder, dtype=np.int64)
