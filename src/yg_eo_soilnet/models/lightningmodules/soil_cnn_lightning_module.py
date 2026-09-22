from __future__ import annotations

import logging
from typing import Any, Mapping, Optional, Sequence

import torch
from torch import nn

from yg_eo_soilnet.models.lightningmodules._regression_base import (
    SoilRegressionLightningBase,
    as_float_list,
    as_float_matrix,
    batch_get,
)
from yg_eo_soilnet.models.lightningmodules.mlp import build_mlp_stack
from yg_eo_soilnet.models.lightningmodules.spatial_encoders import HarmonicPositionEncoder
from yg_eo_soilnet.models.lightningmodules.tabular_encoders import TabularStaticEncoder
from yg_eo_soilnet.models.lightningmodules.temporal_cnn_encoders import (
    AnnualGrid2DEncoder,
    AttentionFusion,
    CalendarGridRasterizer,
    ConcatGatedFusion,
    DilatedTempCNNEncoder,
)

logger = logging.getLogger(__name__)

FUSION_TYPES = ("gated", "attention")
STATIC_TOKEN_MODES = ("summary", "per_feature")


def _as_width_list(value: Any) -> list[int]:
    """`64` and `[64]` both mean one 64-wide block, so a scalar in the config still works."""
    if isinstance(value, (list, tuple)):
        return [int(width) for width in value]
    return [int(value)]


class SoilCNNLightningModule(SoilRegressionLightningBase):
    """Static covariates plus one convolutional encoder per modality over a calendar grid.

        x_static ---> static_encoder --------------------------------.
                                                                      \\
        sequences[m] + mask + time + validity                          \\
                 |                                                      >-- fusion ------------.
                 '--> CalendarGridRasterizer ---> CNN_m ---> concat ---/   gated | attention   |
                      (ragged -> years x months)                      /                        |
        x_coords ---> HarmonicPositionEncoder ----------------------'                         |
        (train-bbox normalized lat/lon; absent unless USE_HARMONIC_COORDS)                     v
                                                                                            concat --> MLP head --> (+ base)
        auxiliary lab block  (auxiliary_enabled) -------------------------------------------'  |
        residual base block  (residual_enabled) ---------------------------------------------'

    Convolution replaces recurrence, so every month is processed in parallel and annual seasonality
    is a property of the receptive field rather than something the network has to learn to remember.
    Two variants share the rasteriser and differ only in how they read the grid:

    * ``dilated_tempcnn`` flattens it and uses ``dilation=12`` to link month *t* to month *t-12*;
    * ``annual_grid2d`` keeps it 2D and factorises the kernel into a months pass and a years pass.

    Any number of modalities of any width is supported: everything is driven by ``modality_dims``.

    Three independent switches shape the rest, and every combination builds. Each module is
    constructed exactly once, so the weights a seed produces depend only on the modules the
    configuration actually uses. SoilResidualCNNLightningModule and
    SoilResidualAttentionCNNLightningModule remain as legacy names for two of the combinations.

    ``fusion`` picks how the static, temporal and coordinate branches are combined:

    * ``gated`` - ConcatGatedFusion, a self-gate over the concatenation that rescales each feature.
    * ``attention`` - AttentionFusion: every branch chunk becomes a token and the tokens attend to one
      another, so a branch is rebuilt from the others before the head sees it.
      ``attention_static_tokens`` picks how the static covariates become tokens. ``summary`` makes
      TabularStaticEncoder's output ONE token. ``per_feature`` makes every continuous column its own
      token and every categorical embedding another, FT-Transformer style; the encoder is then built
      without its MLP, keeping its embeddings and ``continuous_norm``, and ``static_hidden_dims`` has
      no effect.

    ``auxiliary_enabled`` with ``auxiliary_label_columns`` appends MEASURED lab values to the fused
    vector, just before the head. This is an explicit opt-out of the rule that a label is never a
    feature, and it is only sound when the named values are genuinely available at inference time too
    - predicting organic matter for a sample whose texture and pH were measured, say. Naming a column
    that is also being fitted raises rather than being filtered out.

    ``residual_enabled`` makes the head learn a CORRECTION to an existing prediction rather than the
    value. ``residual_base_columns`` nominates one column of the lab roster as the base for each
    fitted target - in practice a ``<target>__<model>`` column written by ``predictions_export`` and
    merged back into the static or targets source. The base is mapped into the target's own space
    and added to the readout::

        b_raw = x_labels[:, i] * label_scale[i] + label_mean[i]      # undo the LAB standardizer
        b_std = (10*log1p(b_raw) - target_mean) / target_scale       # into the TARGET's space
        pred  = b_std + output_head(fused)

    The offset lives entirely inside ``forward``: ``y`` is already in that space, so the loss, the
    epoch metrics, ``predict_step``'s inversion, the uncertainty ensemble and the serving path all work
    unchanged. For the same reason ``val_loss`` is the loss of the final prediction, comparable with a
    run without the base as long as both share the target, split, target_transform and loss_name. The
    base ALSO enters the network as an input, through a block of its own concatenated after the
    fusion beside the auxiliary block - without it the head would be correcting blind.

    LEAKAGE: a base column clears the auxiliary check only because ``c_e_c_meq_100g__soil_cnn`` is a
    different string from ``c_e_c_meq_100g``. That is right in principle - a prediction exists at
    inference time and the measurement does not - but it is only SOUND if those predictions were
    produced out-of-fold with respect to the split this run uses, which nothing here can verify. A
    warning naming each base column is emitted at construction.

    ``coord_dim`` optionally adds a third branch reading the point's own position. It is 0 unless
    the data carries coordinates, which happens only under ``USE_HARMONIC_COORDS``; at 0 the branch
    is an ``nn.Identity`` contributing no parameters and no state_dict keys, so a model built
    without it is indistinguishable from one built before the option existed. Unlike the temporal
    branch, which is built so that nothing encodes an absolute epoch, this one encodes absolute
    position deliberately - that is the signal - and the train bounding box that anchors it travels
    in the datamodule's preprocessing state.
    """

    # Mirrored on the class as well as set per instance. A model logged to MLflow is a pickle, and
    # unpickling restores the instance __dict__ only - so a model pickled before these switches
    # existed reads them from its class, where each legacy name declares the values it was built with.
    fusion_type = "gated"
    attention_static_tokens = "summary"
    auxiliary_enabled = True
    residual_enabled = False

    def __init__(
        self,
        static_dim: int,
        target_dim: int,
        target_names: Optional[Sequence[str]] = None,
        fitted_target_names: Optional[Sequence[str]] = None,
        categorical_cardinalities: Optional[Sequence[int]] = None,
        categorical_vocabularies: Optional[Sequence[Sequence[str]]] = None,
        categorical_feature_names: Optional[Sequence[str]] = None,
        embedding_dims: Any = None,
        embedding_dropout: float = 0.0,
        embedding_max_dim: int = 50,
        continuous_norm: str = "none",
        modality_dims: Optional[Mapping[str, int]] = None,
        temporal_enabled: bool = True,
        grid_years: Optional[int] = None,
        temporal_encoder: str = "dilated_tempcnn",
        cnn_hidden_dims: Any = (32,),
        modality_embed_dim: Any = 32,
        cnn_norm: str = "batch",
        pool: str = "masked_avg",
        month_positional: bool = True,
        use_validity_channels: bool = True,
        auxiliary_label_columns: Optional[Sequence[str]] = None,
        auxiliary_available_names: Optional[Sequence[str]] = None,
        auxiliary_validity_channels: bool = True,
        auxiliary_hidden_dims: Optional[Sequence[int]] = None,
        auxiliary_dropout: float = 0.0,
        # --- harmonic coordinate branch -----------------------------------------------------
        # Inert at coord_dim=0, which is what the datamodule reports unless USE_HARMONIC_COORDS put
        # coordinates on the bundle. See spatial_encoders.HarmonicPositionEncoder.
        coord_dim: int = 0,
        harmonic_num_frequencies: int = 6,
        harmonic_include_input: bool = True,
        harmonic_hidden_dims: Optional[Sequence[int]] = None,
        harmonic_dropout: float = 0.0,
        static_hidden_dims: Sequence[int] = (64,),
        head_hidden_dims: Sequence[int] = (128, 64),
        head_norm_final: bool = False,
        dropout: float = 0.1,
        loss_name: str = "mse",
        huber_delta: float = 1.0,
        # --- structure-aware losses ---------------------------------------------------------
        # Inert unless loss_name is mahalanobis / correlation_penalty / cosine; see
        # lightningmodules/losses.py. target_covariance is injected by LightningConfigFactory
        # from the datamodule's training split, exactly as target_mean/target_scale are.
        loss_base: str = "mse",
        loss_lambda: float = 0.1,
        loss_shrinkage: float = 0.05,
        loss_min_batch: int = 16,
        cosine_space: str = "original",
        target_covariance: Optional[Any] = None,
        learning_rate: float = 1e-3,
        optimizer_name: str = "adamw",
        weight_decay: float = 1e-4,
        scheduler_type: str = "plateau",
        scheduler_factor: float = 0.5,
        scheduler_patience: int = 5,
        scheduler_min_lr: float = 1e-6,
        scheduler_monitor: str = "val_loss",
        target_mean: Optional[Any] = None,
        target_scale: Optional[Any] = None,
        target_transform: Optional[str] = None,
        # Emit (mu, log var) instead of mu alone, and train with beta-NLL. Set by the factory from
        # uncertainty.heteroscedastic; see SoilRegressionLightningBase._beta_nll_loss.
        predict_variance: bool = False,
        beta_nll: float = 0.5,
        *,
        # --- auxiliary switch ---------------------------------------------------------------
        # False ignores auxiliary_label_columns without clearing it, so the list survives in
        # hyper_parameters and switching back needs no second edit. True by default: a checkpoint
        # written before the switch existed used exactly the columns it lists.
        auxiliary_enabled: bool = True,
        # --- fusion -------------------------------------------------------------------------
        # "gated" (ConcatGatedFusion) or "attention" (AttentionFusion). The attention_* settings
        # are read only under "attention".
        fusion: str = "gated",
        attention_static_tokens: str = "summary",
        attention_d_model: int = 64,
        attention_nhead: int = 4,
        attention_num_layers: int = 2,
        attention_ff_multiplier: int = 2,
        attention_dropout: float = 0.1,
        attention_readout: str = "cls",
        # --- residual base ------------------------------------------------------------------
        # The residual_* settings are read only when residual_enabled is true; see the class
        # docstring for what the base is and why it must be out-of-fold.
        residual_enabled: bool = False,
        residual_base_columns: Optional[Mapping[str, str]] = None,
        residual_base_hidden_dims: Optional[Sequence[int]] = None,
        residual_base_dropout: float = 0.0,
        residual_base_validity_channels: bool = True,
        residual_base_max_missing: float = 0.05,
        # Full-roster lab standardization stats, injected by LightningConfigFactory exactly as
        # target_mean/target_scale are. They are what maps the base out of the lab standardizer;
        # without them the offset would be a z-score.
        auxiliary_label_mean: Optional[Any] = None,
        auxiliary_label_scale: Optional[Any] = None,
    ):
        super().__init__()
        # Coerce BEFORE save_hyperparameters(): it captures this frame's locals, and a numpy array
        # stored in hyper_parameters makes the checkpoint unloadable under torch.load's
        # weights_only=True default (PyTorch >= 2.6).
        target_mean = as_float_list(target_mean)
        target_scale = as_float_list(target_scale)
        target_covariance = as_float_matrix(target_covariance)
        head_hidden_dims = [int(width) for width in head_hidden_dims]
        static_hidden_dims = [int(width) for width in static_hidden_dims]
        # Same reason: plain builtins only in hyper_parameters. The vocabularies live here rather
        # than in the datamodule so the checkpoint carries its own label->index mapping and can be
        # applied to a frame it has never seen.
        categorical_cardinalities = [int(value) for value in (categorical_cardinalities or [])]
        categorical_vocabularies = [
            [str(category) for category in vocabulary] for vocabulary in (categorical_vocabularies or [])
        ]
        categorical_feature_names = [str(name) for name in (categorical_feature_names or [])]
        # Same reason again, plus one of its own: the selected names and the roster they were
        # resolved against both travel in hyper_parameters, so the checkpoint records which lab
        # columns it expects instead of re-deriving positions from whatever frame it is handed.
        auxiliary_label_columns = [str(name) for name in (auxiliary_label_columns or [])]
        auxiliary_available_names = [str(name) for name in (auxiliary_available_names or [])]
        auxiliary_hidden_dims = [int(width) for width in (auxiliary_hidden_dims or [])]
        # Same reason: a tuple default and a YAML list must both land in hyper_parameters as a
        # plain list of ints, or the checkpoint stops reloading under weights_only=True.
        harmonic_hidden_dims = [int(width) for width in (harmonic_hidden_dims or [])]
        target_names = [str(name) for name in (target_names or [])]
        # Every target the RUN fits, which under per-target grouping is a superset of this model's
        # outputs. Defaults to target_names so a hand-built module keeps the old behaviour.
        fitted_target_names = [str(name) for name in (fitted_target_names or target_names)]
        auxiliary_enabled = bool(auxiliary_enabled)
        fusion = str(fusion).lower()
        if fusion not in FUSION_TYPES:
            raise ValueError(f"fusion must be one of {list(FUSION_TYPES)}, got {fusion!r}")
        attention_static_tokens = str(attention_static_tokens).lower()
        if fusion == "attention" and attention_static_tokens not in STATIC_TOKEN_MODES:
            raise ValueError(
                f"attention_static_tokens must be one of {list(STATIC_TOKEN_MODES)}, "
                f"got {attention_static_tokens!r}"
            )
        attention_d_model = int(attention_d_model)
        attention_nhead = int(attention_nhead)
        attention_num_layers = int(attention_num_layers)
        attention_ff_multiplier = int(attention_ff_multiplier)
        attention_dropout = float(attention_dropout)
        attention_readout = str(attention_readout).lower()
        residual_enabled = bool(residual_enabled)
        residual_base_columns = {
            str(target): str(column) for target, column in dict(residual_base_columns or {}).items()
        }
        residual_base_hidden_dims = [int(width) for width in (residual_base_hidden_dims or [])]
        # `or []` because as_float_list passes None straight through, and the width check in
        # _build_residual_base_encoder - the one thing standing between a missing statistic and an
        # offset expressed as a z-score - needs a length rather than a TypeError.
        auxiliary_label_mean = as_float_list(auxiliary_label_mean) or []
        auxiliary_label_scale = as_float_list(auxiliary_label_scale) or []
        self.save_hyperparameters()

        self._init_regression_targets(
            target_dim=target_dim,
            target_names=target_names,
            target_mean=target_mean,
            target_scale=target_scale,
            target_transform=target_transform,
            predict_variance=predict_variance,
            beta_nll=beta_nll,
            loss_name=loss_name,
            huber_delta=huber_delta,
            loss_base=loss_base,
            loss_lambda=loss_lambda,
            loss_shrinkage=loss_shrinkage,
            loss_min_batch=loss_min_batch,
            cosine_space=cosine_space,
            target_covariance=target_covariance,
            learning_rate=learning_rate,
            optimizer_name=optimizer_name,
            weight_decay=weight_decay,
            scheduler_type=scheduler_type,
            scheduler_factor=scheduler_factor,
            scheduler_patience=scheduler_patience,
            scheduler_min_lr=scheduler_min_lr,
            scheduler_monitor=scheduler_monitor,
        )

        # static_dim counts the CONTINUOUS covariates only; the categorical ones arrive separately as
        # indices and contribute their embedding widths instead.
        self.static_dim = int(static_dim)
        self.static_hidden_dims = list(static_hidden_dims)
        # The fused vector is sized off the static branch's OUTPUT width, which is its last block.
        self.static_hidden_dim = self.static_hidden_dims[-1]
        # A checkpoint may carry vocabularies without cardinalities; they are redundant by
        # construction (cardinality == len(vocabulary) + 1), so derive rather than demand both.
        if not categorical_cardinalities and categorical_vocabularies:
            categorical_cardinalities = [len(vocabulary) + 1 for vocabulary in categorical_vocabularies]
        self.categorical_cardinalities = list(categorical_cardinalities)
        self.categorical_vocabularies = list(categorical_vocabularies)
        self.categorical_feature_names = list(categorical_feature_names) or [
            f"categorical_{index}" for index in range(len(self.categorical_cardinalities))
        ]
        self.temporal_encoder_name = str(temporal_encoder).lower()
        if self.temporal_encoder_name not in {"dilated_tempcnn", "annual_grid2d"}:
            raise ValueError(
                f"temporal_encoder must be 'dilated_tempcnn' or 'annual_grid2d', got {temporal_encoder!r}"
            )
        # None means "infer the span from each batch". Safe because masked pooling makes an
        # embedding independent of how many empty year-rows a grid carries, but an injected
        # grid_years keeps the grid identical from batch to batch, which is one less thing to reason
        # about when comparing runs.
        self.grid_years = None if grid_years in (None, 0) else max(1, int(grid_years))

        self.modality_dims = {
            str(name).lower(): int(dim)
            for name, dim in dict(modality_dims or {}).items()
            if dim is not None and int(dim) > 0
        }
        self.temporal_enabled = bool(temporal_enabled) and bool(self.modality_dims)
        self._cnn_hidden_dims = cnn_hidden_dims
        self._modality_embed_dim = modality_embed_dim

        # Before the static encoder: per_feature tokens change how it is built.
        self.fusion_type = fusion
        self.attention_static_tokens = attention_static_tokens
        self.static_encoder = self._build_static_encoder(
            dropout,
            embedding_dims=embedding_dims,
            embedding_dropout=embedding_dropout,
            embedding_max_dim=embedding_max_dim,
            continuous_norm=continuous_norm,
        )

        self.rasterizers = nn.ModuleDict()
        self.temporal_encoders = nn.ModuleDict()
        if self.temporal_enabled:
            for modality_name, modality_dim in self.modality_dims.items():
                rasterizer = CalendarGridRasterizer(
                    num_channels=modality_dim,
                    grid_years=self.grid_years,
                    use_validity_channels=use_validity_channels,
                    month_positional=month_positional,
                )
                self.rasterizers[modality_name] = rasterizer
                encoder_cls = (
                    DilatedTempCNNEncoder
                    if self.temporal_encoder_name == "dilated_tempcnn"
                    else AnnualGrid2DEncoder
                )
                self.temporal_encoders[modality_name] = encoder_cls(
                    num_channels=rasterizer.output_channels,
                    output_dim=int(
                        self._per_modality_value(
                            self._modality_embed_dim, modality_name, "modality_embed_dim"
                        )
                    ),
                    hidden_dims=_as_width_list(
                        self._per_modality_value(self._cnn_hidden_dims, modality_name, "cnn_hidden_dims")
                    ),
                    dropout=dropout,
                    norm=cnn_norm,
                    pool=pool,
                )

        self.target_names = list(target_names)
        self.fitted_target_names = list(fitted_target_names)
        self.auxiliary_enabled = auxiliary_enabled
        self.auxiliary_validity_channels = bool(auxiliary_validity_channels)
        self.auxiliary_encoder = self._build_auxiliary_encoder(
            auxiliary_label_columns if auxiliary_enabled else [],
            auxiliary_available_names,
            auxiliary_hidden_dims,
            auxiliary_dropout,
        )

        self.coordinate_encoder = self._build_coordinate_encoder(
            coord_dim,
            harmonic_num_frequencies,
            harmonic_include_input,
            harmonic_hidden_dims,
            harmonic_dropout,
        )

        # After the auxiliary branch: the base is resolved against the same roster, and checked
        # against the columns that branch actually reads.
        self.residual_enabled = residual_enabled
        self.residual_base_columns = residual_base_columns
        self.residual_base_validity_channels = bool(residual_base_validity_channels)
        self.residual_base_max_missing = float(residual_base_max_missing)
        self.base_encoder = self._build_residual_base_encoder(
            auxiliary_label_mean,
            auxiliary_label_scale,
            residual_base_hidden_dims,
            float(residual_base_dropout),
        )

        self.fusion = self._build_fusion(
            d_model=attention_d_model,
            nhead=attention_nhead,
            num_layers=attention_num_layers,
            ff_multiplier=attention_ff_multiplier,
            dropout=attention_dropout,
            readout=attention_readout,
        )
        # Built once, last, off the widths every block above settled on. The residual and attention
        # variants used to build a head here and then replace it, spending parameters and random
        # draws on modules that were thrown away.
        self.output_head = build_mlp_stack(
            self.fusion.output_dim + self.auxiliary_output_dim + self.residual_base_output_dim,
            head_hidden_dims,
            # head_output_dim, not target_dim: a heteroscedastic head is twice as wide
            # because it emits a log variance beside every mean.
            self.head_output_dim,
            dropout=dropout,
            activation="gelu",
            norm_final=bool(head_norm_final),
        )

    # --- construction helpers ----------------------------------------------

    def _per_modality_value(self, setting: Any, modality_name: str, label: str) -> Any:
        """One setting for every modality, or a Mapping that must name every modality.

        Returns the raw value; callers coerce. `cnn_hidden_dims` is a *list* per modality, so
        coercing to int here would be wrong for it.
        """
        if isinstance(setting, Mapping):
            value = setting.get(modality_name, setting.get(str(modality_name).lower()))
            if value is None:
                # Silently defaulting here would hand a newly added modality the old width,
                # undoing the per-branch sizing without any signal.
                raise ValueError(
                    f"Modality {modality_name!r} has no entry in {label} "
                    f"(configured: {sorted(setting)}). Add one for it, or use a single value "
                    "to apply the same setting to every modality."
                )
            return value
        return setting

    @property
    def _static_tokens_per_feature(self) -> bool:
        return self.fusion_type == "attention" and self.attention_static_tokens == "per_feature"

    def _static_token_dims(self) -> list[int]:
        """How the static vector reaching an attention fusion is cut into tokens.

        ``summary`` reads the static branch as one token, including a zero-filled one when there are
        no static features at all. ``per_feature`` with no static features has nothing to cut, and
        the fusion then reads no static tokens.
        """
        if self.attention_static_tokens == "summary":
            return [self.static_hidden_dim]
        if not self.has_static_features:
            return []
        return [1] * self.static_dim + list(self.static_encoder.embedding_dims)

    def _build_fusion(self, **attention: Any) -> nn.Module:
        """ConcatGatedFusion or AttentionFusion. The two share a call signature on purpose, so
        :meth:`_fuse` and :meth:`_fuse_from_parts` drive either one without knowing which they hold.
        """
        # ModuleDict order is the order _encode_temporal_from_grids concatenates in.
        temporal_dims = [encoder.output_dim for encoder in self.temporal_encoders.values()]
        if self.fusion_type == "attention":
            return AttentionFusion(
                self._static_token_dims(), temporal_dims, self.coordinate_output_dim, **attention
            )
        # The static branch keeps its width even when static_dim is 0, so the fused vector has a
        # fixed shape regardless of whether covariates are present.
        return ConcatGatedFusion(self.static_hidden_dim, sum(temporal_dims), self.coordinate_output_dim)

    def _build_auxiliary_encoder(
        self,
        selected: list[str],
        available: list[str],
        hidden_dims: list[int],
        dropout: float,
    ) -> nn.Module:
        """Resolve the named lab columns to positions and build the branch that reads them.

        The selection is by NAME against the roster the datamodule offers, resolved once into a
        buffer. Positions cannot be configured directly: the bundle's column order follows
        LABEL_COLUMNS, so an index would silently point at a different measurement the moment that
        list is reordered.
        """
        self.auxiliary_label_columns = list(selected)
        self.auxiliary_available_names = list(available)
        self.auxiliary_output_dim = 0
        # Registered even when empty so state_dict keys do not depend on the configuration, and a
        # checkpoint trained without auxiliary columns still loads into a module that declares them.
        self.register_buffer("auxiliary_index", torch.zeros(0, dtype=torch.long), persistent=True)
        if not selected:
            return nn.Identity()

        if not self.fitted_target_names:
            # Without the target roster the leakage check below cannot run, and silently skipping
            # it is how a model ends up reading its own answer. The config factory always supplies
            # these, so this only fires on hand-built modules.
            raise ValueError(
                "auxiliary_label_columns requires target_names so a selected column can be checked "
                "against what is being fitted; pass target_names explicitly."
            )

        # Checked against every target the RUN fits, not just this model's outputs. Under
        # per-target grouping the two differ, and checking the narrower list would admit a sibling
        # target as an input - which leaks the answer just as surely, via whatever correlation the
        # two share.
        leaking = [name for name in selected if name in set(self.fitted_target_names)]
        if leaking:
            raise ValueError(
                f"auxiliary_label_columns may not name a column being fitted: {sorted(leaking)} "
                f"also appear(s) in the run's targets {sorted(self.fitted_target_names)}. The model "
                "would read a target as an input."
            )

        if not available:
            # Distinguished from the unknown-name case below because the fix is somewhere else
            # entirely: the columns may well exist and be correctly declared, and still not have
            # been carried. Reporting "unknown column" here sends the reader to audit a config that
            # is already right.
            raise ValueError(
                f"auxiliary_label_columns names {sorted(selected)} but no lab columns are being "
                "carried with the data. Set CARRY_LABEL_COLUMNS: true in data_spec.yml to make the "
                "LABEL_COLUMNS entries available as auxiliary inputs."
            )

        unknown = [name for name in selected if name not in set(available)]
        if unknown:
            raise ValueError(
                f"auxiliary_label_columns names column(s) the data does not carry: {sorted(unknown)}. "
                f"Available: {sorted(available)}. A lab column must be listed in LABEL_COLUMNS and "
                "present in the static or targets source to be selectable."
            )

        duplicates = sorted({name for name in selected if selected.count(name) > 1})
        if duplicates:
            raise ValueError(f"auxiliary_label_columns lists duplicate column(s): {duplicates}")

        self.auxiliary_index = torch.as_tensor([available.index(name) for name in selected], dtype=torch.long)
        # Validity doubles the width: one measured/filled flag per selected column, so the network
        # can discount a train-median fill instead of reading it as a measurement.
        input_dim = len(selected) * (2 if self.auxiliary_validity_channels else 1)
        # An empty hidden_dims makes this an Identity, which IS the raw-concat mode - the two
        # options are one code path, and forward() needs no branch between them.
        encoder = build_mlp_stack(
            input_dim,
            hidden_dims,
            None,
            dropout=dropout,
            activation="gelu",
            use_layer_norm=True,
            # This block feeds the head's input vector rather than a readout, so both are on - the
            # case build_mlp_stack's docstring describes as "feeding a fusion".
            norm_final=True,
            dropout_final=True,
        )
        self.auxiliary_output_dim = hidden_dims[-1] if hidden_dims else input_dim
        return encoder

    def _build_residual_base_encoder(
        self,
        label_mean: list[float],
        label_scale: list[float],
        hidden_dims: list[int],
        dropout: float,
    ) -> nn.Module:
        """Resolve one base column per fitted target and build the block that reads them.

        Resolution is by name against the same roster the auxiliary branch uses, and for the same
        reason: the roster's order follows LABEL_COLUMNS, so a configured index would point at a
        different measurement the moment that list is reordered.
        """
        self.residual_base_output_dim = 0
        if not self.residual_enabled:
            # Nothing registered, not even empty buffers. Every checkpoint written without a base -
            # all of soil_cnn's before this switch existed - carries no residual keys and must keep
            # loading strictly; with the switch on, the buffers below are exactly the ones the
            # residual class always registered, so those checkpoints load too.
            return nn.Identity()

        self.register_buffer("residual_base_index", torch.zeros(0, dtype=torch.long), persistent=True)
        self.register_buffer("residual_base_label_mean", torch.zeros(0), persistent=True)
        self.register_buffer("residual_base_label_scale", torch.ones(0), persistent=True)

        selected = self.residual_base_columns
        if not selected:
            # An empty mapping with the switch on means there is nothing to be a residual OF.
            # Silently degrading to a plain head would train a model other than the one configured,
            # with only the metrics to say which one actually ran.
            raise ValueError(
                "residual_base_columns is required when residual_enabled is true: the head anchors on "
                "a base prediction per target. Set residual_enabled: false for a model with no base."
            )

        missing = [name for name in self.target_names if name not in selected]
        if missing:
            raise ValueError(
                f"residual_base_columns has no entry for target(s) {sorted(missing)}; it must name a "
                f"base column for every target this model fits ({sorted(self.target_names)}). A "
                "partially anchored head would learn residuals for some outputs and absolute values "
                "for others, against a single loss."
            )

        extra = [name for name in selected if name not in set(self.target_names)]
        if extra:
            raise ValueError(
                f"residual_base_columns names target(s) this model does not fit: {sorted(extra)}. "
                f"This model's targets are {sorted(self.target_names)}."
            )

        # The measured target itself, rather than a prediction of it. The auxiliary check never sees
        # this mapping, so the same rail has to be laid here.
        leaking = [column for column in selected.values() if column in set(self.fitted_target_names)]
        if leaking:
            raise ValueError(
                f"residual_base_columns may not name a column being fitted: {sorted(leaking)} "
                f"also appear(s) in the run's targets {sorted(self.fitted_target_names)}. The base "
                "must be a PREDICTION of the target, not the target."
            )

        shared = sorted(set(selected.values()) & set(self.auxiliary_label_columns))
        if shared:
            raise ValueError(
                f"Column(s) {shared} appear in both residual_base_columns and "
                "auxiliary_label_columns. A base column already reaches the head through its own "
                "block; listing it twice feeds it twice and lets the two roles be configured apart."
            )

        available = list(self.auxiliary_available_names)
        if not available:
            raise ValueError(
                f"residual_base_columns names {sorted(set(selected.values()))} but no lab columns "
                "are being carried with the data. Set CARRY_LABEL_COLUMNS: true in data_spec.yml, "
                "and list the base column(s) in LABEL_COLUMNS."
            )

        unknown = [column for column in selected.values() if column not in set(available)]
        if unknown:
            raise ValueError(
                f"residual_base_columns names column(s) the data does not carry: {sorted(unknown)}. "
                f"Available: {sorted(available)}. A base column must be listed in LABEL_COLUMNS and "
                "present in the static or targets source."
            )

        if len(label_mean) != len(available) or len(label_scale) != len(available):
            # Without these the base cannot leave the lab standardizer's space, and adding it as-is
            # would offset the prediction by a z-score. The factory supplies them from the training
            # split; this only fires on a hand-built module.
            raise ValueError(
                "residual_base_columns requires auxiliary_label_mean and auxiliary_label_scale at "
                f"the roster's width ({len(available)}); got {len(label_mean)} and "
                f"{len(label_scale)}. They are what maps the base out of the lab standardizer."
            )

        # Ordered by target_names, so position j of the offset lines up with output column j.
        indices = [available.index(selected[name]) for name in self.target_names]
        self.residual_base_index = torch.as_tensor(indices, dtype=torch.long)
        self.residual_base_label_mean = torch.as_tensor(
            [label_mean[index] for index in indices], dtype=torch.float32
        )
        self.residual_base_label_scale = torch.as_tensor(
            [label_scale[index] for index in indices], dtype=torch.float32
        )

        logger.warning(
            "%s anchors on %s. These must be OUT-OF-FOLD predictions for the split this run uses: "
            "nothing in the pipeline can verify that, and in-fold predictions will inflate every "
            "reported metric.",
            type(self).__name__,
            {name: selected[name] for name in self.target_names},
        )

        input_dim = self.target_dim * (2 if self.residual_base_validity_channels else 1)
        # An empty hidden_dims makes this an Identity, which IS the raw-concat mode - the same shape
        # the auxiliary and harmonic blocks use, and for the same reason.
        encoder = build_mlp_stack(
            input_dim,
            hidden_dims,
            None,
            dropout=dropout,
            activation="gelu",
            use_layer_norm=True,
            # This block feeds the head's input vector rather than a readout, so both are on.
            norm_final=True,
            dropout_final=True,
        )
        self.residual_base_output_dim = hidden_dims[-1] if hidden_dims else input_dim
        return encoder

    def _build_coordinate_encoder(
        self,
        coord_dim: Any,
        num_frequencies: int,
        include_input: bool,
        hidden_dims: list[int],
        dropout: float,
    ) -> nn.Module:
        """The harmonic branch, or an ``nn.Identity`` contributing nothing when there are no coords.

        Returning Identity rather than a zero-width encoder is what keeps the promise that this
        option is free when unused: ``nn.Identity`` registers no parameters and no state_dict keys,
        so a model at ``coord_dim=0`` has exactly the parameter count and exactly the key set of one
        built before the branch existed, and a checkpoint from either loads into the other.
        """
        self.coord_dim = int(coord_dim or 0)
        self.coordinate_output_dim = 0
        if self.coord_dim <= 0:
            return nn.Identity()

        encoder = HarmonicPositionEncoder(
            num_coordinates=self.coord_dim,
            num_frequencies=num_frequencies,
            include_input=include_input,
            hidden_dims=hidden_dims,
            dropout=dropout,
        )
        self.coordinate_output_dim = encoder.output_dim
        return encoder

    @property
    def has_coordinates(self) -> bool:
        return self.coord_dim > 0

    @property
    def has_auxiliary_labels(self) -> bool:
        return bool(self.auxiliary_label_columns)

    @property
    def serving_label_columns(self) -> list[str]:
        """The lab columns a served request must supply, i.e. every one the model actually reads.

        The auxiliary columns, plus the base columns when the residual is on. The serving signature
        is built from this, so a column missing here arrives NaN, is median-filled from the training
        split and is flagged unmeasured, with nothing raised. The base is the one column a request
        must never omit: a median-filled base leaves the head correcting the same constant for
        every point.
        """
        auxiliary = list(self.auxiliary_label_columns)
        if not self.residual_enabled:
            return auxiliary
        base = [self.residual_base_columns[name] for name in self.target_names]
        return auxiliary + [column for column in base if column not in set(auxiliary)]

    @property
    def has_static_features(self) -> bool:
        return self.static_dim > 0 or bool(self.categorical_cardinalities)

    def _build_static_encoder(
        self,
        dropout: float,
        *,
        embedding_dims: Any,
        embedding_dropout: float,
        embedding_max_dim: int,
        continuous_norm: str,
    ) -> nn.Module:
        if not self.has_static_features:
            return nn.Identity()
        # No output projection: this branch keeps its full final width, because ConcatGatedFusion
        # gates the concatenation rather than interpolating at a shared width.
        return TabularStaticEncoder(
            num_continuous=self.static_dim,
            hidden_dims=self.static_hidden_dims,
            cardinalities=self.categorical_cardinalities,
            embedding_dims=embedding_dims,
            embedding_dropout=embedding_dropout,
            embedding_max_dim=embedding_max_dim,
            feature_names=self.categorical_feature_names,
            dropout=dropout,
            activation="gelu",
            use_layer_norm=True,
            continuous_norm=continuous_norm,
            # per_feature attention tokens are cut from the raw [continuous_norm(x), embedded] block,
            # so the encoder stops before its MLP. forward reaches it through static_encoder(...) and
            # forward_from_parts through forward_with_embedding, and both return that same block.
            mlp=not self._static_tokens_per_feature,
        )

    # --- coverage guard -----------------------------------------------------

    def on_fit_start(self) -> None:
        """Refuse to train on a base column the data mostly does not carry.

        Nothing upstream checks this: ``assert_columns_are_dense_enough`` inspects only the
        continuous covariates, and lab columns are removed from that block by ``filter_schema``. A
        sparse base is median-filled, so the failure is silent - the head learns to correct a
        constant and the run merely looks mediocre.
        """
        super().on_fit_start()
        if not self.residual_enabled:
            return
        datamodule = getattr(self.trainer, "datamodule", None) if self.trainer is not None else None
        bundle = getattr(datamodule, "sequence_bundle", None)
        if bundle is None or not hasattr(bundle, "label_missing_fraction"):
            return

        offenders = {}
        for name in self.target_names:
            column = self.residual_base_columns[name]
            fraction = float(bundle.label_missing_fraction(column))
            if fraction > self.residual_base_max_missing:
                offenders[column] = round(fraction, 4)
        if offenders:
            raise ValueError(
                f"Base column(s) {offenders} exceed residual_base_max_missing="
                f"{self.residual_base_max_missing}. A missing base is median-filled, so the head "
                "would be correcting the training median rather than a prediction for that point. "
                "Regenerate the predictions over the full population, or raise the threshold "
                "deliberately."
            )

    # --- forward -----------------------------------------------------------

    def _encode_static(
        self, x_static: torch.Tensor, x_categorical: Optional[torch.Tensor]
    ) -> torch.Tensor:
        if not self.has_static_features:
            return torch.zeros(
                (x_static.size(0), self.static_hidden_dim), device=x_static.device, dtype=x_static.dtype
            )
        return self.static_encoder(x_static, x_categorical)

    def _select_coordinates(self, batch: Any, device, dtype) -> Optional[torch.Tensor]:
        """The normalized coordinates as they enter ``coordinate_encoder``.

        Separated from :meth:`_encode_coordinates` for the same reason ``_select_auxiliary`` is
        separated from ``_encode_auxiliary``: an explainer attributes to these two raw columns,
        which mean ``lat`` and ``lon``, rather than to the encoder's output, whose channels are
        sines of them and mean nothing individually.
        """
        if not self.has_coordinates:
            return None

        coords = batch_get(batch, "x_coords")
        if coords is None:
            raise KeyError(
                "Batch is missing 'x_coords'; this model was built with coord_dim="
                f"{self.coord_dim} and needs the normalized coordinates the sequence datamodule "
                "collates under USE_HARMONIC_COORDS."
            )
        coords = coords.to(device=device, dtype=dtype)
        if coords.size(-1) != self.coord_dim:
            # The alternative is a silent axis swap: at the wrong width the encoder would read
            # longitude out of the latitude column and still return a well-shaped tensor.
            raise ValueError(
                f"Batch carries {coords.size(-1)} coordinate column(s) but this model was built "
                f"for {self.coord_dim}."
            )
        return coords

    def _encode_coordinates(self, batch: Any, device, dtype) -> Optional[torch.Tensor]:
        coords = self._select_coordinates(batch, device=device, dtype=dtype)
        if coords is None:
            return None
        return self.coordinate_encoder(coords)

    def _select_auxiliary(self, batch: Any, device, dtype) -> Optional[torch.Tensor]:
        """The auxiliary lab block as it enters ``auxiliary_encoder``: values, then validity flags.

        Separated from :meth:`_encode_auxiliary` so an explainer can attribute to these raw
        per-column inputs rather than to the encoder's output, which has no per-column meaning.
        """
        if not self.has_auxiliary_labels:
            return None

        values = batch_get(batch, "x_labels")
        if values is None:
            raise KeyError(
                "Batch is missing 'x_labels'; auxiliary_label_columns needs the measured lab values "
                f"({self.auxiliary_label_columns}) that the sequence datamodule collates."
            )
        values = values.to(device=device, dtype=dtype)
        if values.size(-1) != len(self.auxiliary_available_names):
            # Positions were resolved against the roster this model was BUILT with. A batch of a
            # different width means it is not that roster, and index_select would then quietly read
            # whichever measurement now sits at that position.
            raise ValueError(
                f"Batch carries {values.size(-1)} lab column(s) but this model resolved its "
                f"auxiliary columns against {len(self.auxiliary_available_names)}; the data no "
                "longer matches the checkpoint's label roster."
            )

        selected = values.index_select(-1, self.auxiliary_index)
        if self.auxiliary_validity_channels:
            validity = batch_get(batch, "x_label_validity")
            if validity is None:
                raise KeyError(
                    "Batch is missing 'x_label_validity'; set auxiliary_validity_channels=False to "
                    "run without the measured-vs-filled flags."
                )
            validity = validity.to(device=device, dtype=dtype).index_select(-1, self.auxiliary_index)
            selected = torch.cat([selected, validity], dim=-1)

        return selected

    def _encode_auxiliary(self, batch: Any, device, dtype) -> Optional[torch.Tensor]:
        selected = self._select_auxiliary(batch, device=device, dtype=dtype)
        if selected is None:
            return None
        return self.auxiliary_encoder(selected)

    def _residual_base(self, batch: Any, *, device, dtype) -> torch.Tensor:
        """``[base_in_target_space, validity]`` - the offset and the block, in one tensor.

        One tensor rather than two so :meth:`explanation_parts` can publish a single part from which
        BOTH the encoder input and the additive offset are derived. Splitting them across two parts,
        or reading the offset off the batch, would break the equality
        ``forward_from_parts(explanation_parts(batch)[0]) == forward(batch)`` that
        tests/test_explain_lightning.py pins.
        """
        values = batch_get(batch, "x_labels")
        if values is None:
            raise KeyError(
                "Batch is missing 'x_labels'; residual_base_columns needs the base prediction "
                f"column(s) {sorted(set(self.residual_base_columns.values()))} that the sequence "
                "datamodule collates."
            )
        values = values.to(device=device, dtype=dtype)
        if values.size(-1) != len(self.auxiliary_available_names):
            raise ValueError(
                f"Batch carries {values.size(-1)} lab column(s) but this model resolved its base "
                f"columns against {len(self.auxiliary_available_names)}; the data no longer matches "
                "the checkpoint's label roster."
            )

        base = values.index_select(-1, self.residual_base_index)
        base = base * self.residual_base_label_scale + self.residual_base_label_mean
        if bool(self.targets_are_log1p):
            # Mirrors SoilSequenceDataModule._apply_target_transform, clipping included: log1p is
            # undefined below -1 and these targets are non-negative, so a base that came back
            # slightly negative is clipped exactly as a measured value would be.
            base = 10.0 * torch.log1p(base.clamp_min(0.0))
        if bool(self.targets_are_standardized):
            base = (base - self.target_mean) / self.target_scale

        if not self.residual_base_validity_channels:
            return base

        validity = batch_get(batch, "x_label_validity")
        if validity is None:
            raise KeyError(
                "Batch is missing 'x_label_validity'; set residual_base_validity_channels=False to "
                "run without the measured-vs-filled flags."
            )
        validity = validity.to(device=device, dtype=dtype).index_select(-1, self.residual_base_index)
        return torch.cat([base, validity], dim=-1)

    def _head_from_base(self, fused: torch.Tensor, block: torch.Tensor) -> torch.Tensor:
        """Widen the fused vector with the base block, run the head, and add the offset back.

        Returns the readout in its raw shape, so ``_split_head_output`` still applies.
        """
        fused = torch.cat([fused, self.base_encoder(block)], dim=-1)
        mean, log_variance = self._split_head_output(self.output_head(fused))
        mean = mean + block[..., : self.target_dim]
        if log_variance is None:
            return mean
        # The offset belongs to the MEAN half only. On a heteroscedastic head the readout is
        # 2*target_dim wide, and adding it to the whole tensor would shift the log variances too -
        # turning a base of 40 into a predicted variance of exp(40).
        return torch.cat([mean, log_variance], dim=-1)

    def _rasterize(self, batch: Any, device, dtype) -> dict[str, tuple[torch.Tensor, torch.Tensor]]:
        """One ``(grid, cell_mask)`` per modality: the ragged sequences laid onto a calendar grid.

        This is the boundary between the non-differentiable part of the temporal branch and the
        differentiable one. The scatter that builds the grid cannot be attributed through, but
        everything downstream of it is convolution and pooling, so a gradient explainer takes these
        grids as its inputs and reaches every individual band.
        """
        sequences = batch_get(batch, "sequences", {}) or {}
        masks = batch_get(batch, "sequence_mask", {}) or {}
        times = batch_get(batch, "sequence_time", {}) or {}
        validities = batch_get(batch, "sequence_validity", {}) or {}

        grids: dict[str, tuple[torch.Tensor, torch.Tensor]] = {}
        for modality_name in self.temporal_encoders:
            values = sequences.get(modality_name)
            mask = masks.get(modality_name)
            modality_times = times.get(modality_name)
            if values is None or mask is None or modality_times is None:
                raise KeyError(
                    f"Batch is missing sequence data for modality '{modality_name}'; expected it in "
                    "'sequences', 'sequence_mask' and 'sequence_time'"
                )
            validity = validities.get(modality_name)
            grids[modality_name] = self.rasterizers[modality_name](
                values.to(device=device, dtype=dtype),
                mask.to(device=device),
                modality_times.to(device=device),
                None if validity is None else validity.to(device=device),
            )
        return grids

    def _encode_temporal_from_grids(
        self, grids: Mapping[str, tuple[torch.Tensor, torch.Tensor]]
    ) -> Optional[torch.Tensor]:
        if not self.temporal_encoders:
            return None

        embeddings = []
        for modality_name, encoder in self.temporal_encoders.items():
            grid, cell_mask = grids[modality_name]
            embedding = encoder(grid, cell_mask)
            # A point with nothing in the window contributes nothing rather than a bias-shaped
            # artefact that the gate would then have to learn to suppress.
            embeddings.append(embedding * cell_mask.flatten(1).any(dim=1, keepdim=True).to(dtype=embedding.dtype))

        return torch.cat(embeddings, dim=-1)

    def _encode_temporal(self, batch: Any, device, dtype) -> Optional[torch.Tensor]:
        if not self.temporal_encoders:
            return None
        return self._encode_temporal_from_grids(self._rasterize(batch, device=device, dtype=dtype))

    def _fuse(self, batch: Any, *, device, dtype) -> torch.Tensor:
        """Every branch, concatenated into the vector the head reads. Everything but the readout.

        Split out of :meth:`forward` so the readout - a plain head, or one anchored on the residual
        base - is chosen in one place, over one trunk that every configuration shares.
        """
        x_static = batch_get(batch, "x_static")
        if x_static is None:
            raise KeyError("Batch is missing 'x_static'")

        x_static = x_static.to(device=device, dtype=dtype)
        x_categorical = batch_get(batch, "x_categorical")
        if x_categorical is not None:
            x_categorical = x_categorical.to(device=device)

        static_features = self._encode_static(x_static, x_categorical)
        temporal_features = self._encode_temporal(batch, device=device, dtype=dtype)
        # Inside the fusion, not appended after it: the fusion reads every branch together, so
        # giving it position lets it damp, admit or re-read the other branches conditioned on where
        # the point is.
        coordinate_features = self._encode_coordinates(batch, device=device, dtype=dtype)
        fused = self.fusion(static_features, temporal_features, coordinate_features)

        # Appended AFTER the fusion, so a measured lab value reaches the head at full strength rather
        # than being traded off against the branches that had to infer it.
        auxiliary_features = self._encode_auxiliary(batch, device=device, dtype=dtype)
        if auxiliary_features is not None:
            fused = torch.cat([fused, auxiliary_features], dim=-1)
        return fused

    def forward(self, batch: Any) -> torch.Tensor:
        reference = next(self.parameters())
        device, dtype = reference.device, reference.dtype
        fused = self._fuse(batch, device=device, dtype=dtype)
        if not self.residual_enabled:
            return self.output_head(fused)
        return self._head_from_base(fused, self._residual_base(batch, device=device, dtype=dtype))

    # --- attribution seam ---------------------------------------------------
    # explanation_parts() splits a batch into the tensors an explainer perturbs, and
    # forward_from_parts() rebuilds the prediction from exactly those tensors. The pair must agree:
    # forward_from_parts(explanation_parts(batch)[0]) has to equal forward(batch) exactly, because
    # any drift between the two silently attributes importance to a model that is not the one being
    # scored. tests/test_explain_lightning.py pins that equality.
    #
    # Neither method is called by forward, _shared_step or predict_step. Training is bit-identical
    # whether or not anything ever explains the model.

    def explanation_parts(self, batch: Any) -> tuple[list[torch.Tensor], list[dict[str, Any]]]:
        """``(parts, groups)`` - the attribution inputs and how to fold them back into features.

        Each group describes one contiguous run of columns in one part tensor, and names the
        feature that run belongs to. Summing a group's SHAP values gives that feature's
        contribution, which is valid because SHAP values are additive.
        """
        reference = next(self.parameters())
        device, dtype = reference.device, reference.dtype

        x_static = batch_get(batch, "x_static")
        if x_static is None:
            raise KeyError("Batch is missing 'x_static'")
        x_static = x_static.to(device=device, dtype=dtype)

        # Context columns are ordinary continuous covariates living in x_static - they are NOT a
        # separate part, and nothing about the forward pass distinguishes them. Only the group's
        # `kind` differs, which is what lets an explainer roll the declared group up as a block
        # instead of scattering it among the other covariates.
        context_names = set(getattr(self, "context_feature_names", None) or [])
        parts: list[torch.Tensor] = [x_static]
        groups: list[dict[str, Any]] = [
            {
                "part": 0,
                "kind": "context" if name in context_names else "static",
                "name": name,
                "columns": [index],
            }
            for index, name in enumerate(self._static_feature_names(x_static.size(-1)))
        ]

        # Categorical: the embedding, not the int64 index, because an index has no gradient. One
        # group per feature, spanning that feature's embedding dimensions.
        if self.has_static_features and self.static_encoder.embeddings.num_features:
            x_categorical = batch_get(batch, "x_categorical")
            if x_categorical is None:
                raise KeyError("Batch is missing 'x_categorical'")
            embedded = self.static_encoder.embeddings(x_categorical.to(device=device)).to(dtype=dtype)
            part_index = len(parts)
            parts.append(embedded)
            cursor = 0
            for name, width in zip(
                self.static_encoder.embeddings.feature_names,
                self.static_encoder.embeddings.embedding_dims,
            ):
                groups.append(
                    {
                        "part": part_index,
                        "kind": "categorical",
                        "name": name,
                        "columns": list(range(cursor, cursor + int(width))),
                    }
                )
                cursor += int(width)

        # Temporal: one part per modality, the rasterized grid. Groups fold each band's value
        # channel together with its validity channel - they describe the same band - and keep the
        # month sin/cos pair as one row of its own.
        grids = self._rasterize(batch, device=device, dtype=dtype) if self.temporal_encoders else {}
        for modality_name in self.temporal_encoders:
            grid, _cell_mask = grids[modality_name]
            part_index = len(parts)
            parts.append(grid)
            layout = self.rasterizers[modality_name].channel_layout()
            column_names = self._modality_column_names(modality_name, len(layout["values"]))
            for band_index, band_name in enumerate(column_names):
                columns = [layout["values"][band_index]]
                if layout["validity"]:
                    columns.append(layout["validity"][band_index])
                groups.append(
                    {
                        "part": part_index,
                        "kind": "temporal",
                        "modality": modality_name,
                        "name": band_name,
                        "columns": columns,
                    }
                )
            if layout["month_positional"]:
                groups.append(
                    {
                        "part": part_index,
                        "kind": "temporal",
                        "modality": modality_name,
                        "name": f"{modality_name}_month_positional",
                        "columns": list(layout["month_positional"]),
                    }
                )

        # Coordinates: the two NORMALIZED columns, not the harmonic channels they expand into. The
        # expansion is differentiable, so forward_from_parts recomputes it and the explainer gets
        # two rows that mean `lat` and `lon` instead of 4*K rows that individually mean nothing.
        coords = self._select_coordinates(batch, device=device, dtype=dtype)
        if coords is not None:
            part_index = len(parts)
            parts.append(coords)
            for index, name in enumerate(self._coordinate_names(coords.size(-1))):
                groups.append(
                    {
                        "part": part_index,
                        "kind": "spatial",
                        "name": name,
                        "columns": [index],
                    }
                )

        # Auxiliary lab block: raw values, followed by validity flags when they are enabled.
        selected = self._select_auxiliary(batch, device=device, dtype=dtype)
        if selected is not None:
            part_index = len(parts)
            parts.append(selected)
            count = len(self.auxiliary_label_columns)
            for index, name in enumerate(self.auxiliary_label_columns):
                columns = [index]
                if self.auxiliary_validity_channels:
                    columns.append(count + index)
                groups.append(
                    {
                        "part": part_index,
                        "kind": "auxiliary",
                        "name": name,
                        "columns": columns,
                    }
                )

        # Residual base: last, as one part carrying both the block and the offset - see
        # _residual_base for why they cannot be split.
        if self.residual_enabled:
            block = self._residual_base(batch, device=device, dtype=dtype)
            part_index = len(parts)
            parts.append(block)
            for index, name in enumerate(self.target_names):
                columns = [index]
                if self.residual_base_validity_channels:
                    columns.append(self.target_dim + index)
                groups.append(
                    {
                        "part": part_index,
                        "kind": "residual_base",
                        "name": self.residual_base_columns[name],
                        "target": name,
                        "columns": columns,
                    }
                )

        return parts, groups

    def forward_from_parts(self, parts: Sequence[torch.Tensor]) -> torch.Tensor:
        """Rebuild a prediction from :meth:`explanation_parts` output, and nothing else.

        A pure function of ``parts`` on purpose. A gradient explainer evaluates the model on
        interpolations between a sample and random background rows, so anything the forward pass
        needs has to be derivable from the perturbed tensors themselves - it cannot be captured from
        the original batch, because the row count and the row identities both change.

        ``cell_mask`` is therefore read back out of the grid rather than passed alongside it: the
        rasterizer already writes it as the ``cell_observed`` channel, so the grid is self-contained.
        """
        fused, cursor = self._fuse_from_parts(parts)
        if self.residual_enabled:
            raw = self._head_from_base(fused, parts[cursor])
        else:
            raw = self.output_head(fused)
        # The MEAN only. On a heteroscedastic head the readout is 2*target_dim wide, and returning
        # it whole would hand the explainer a second block of outputs that are log variances - which
        # it would attribute and label as targets, producing a SHAP plot with twice the targets the
        # model has, half of them explaining a quantity nobody asked about.
        return self._split_head_output(raw)[0]

    def _fuse_from_parts(self, parts: Sequence[torch.Tensor]) -> tuple[torch.Tensor, int]:
        """``(fused, cursor)`` - :meth:`_fuse`'s counterpart over attribution parts.

        Returns the cursor alongside the vector so the caller knows where the residual base part,
        when there is one, starts.
        """
        cursor = 0
        x_static = parts[cursor]
        cursor += 1

        embedded = None
        if self.has_static_features and self.static_encoder.embeddings.num_features:
            embedded = parts[cursor]
            cursor += 1

        if self.has_static_features:
            static_features = self.static_encoder.forward_with_embedding(x_static, embedded)
        else:
            static_features = torch.zeros(
                (x_static.size(0), self.static_hidden_dim), device=x_static.device, dtype=x_static.dtype
            )

        temporal_features = None
        if self.temporal_encoders:
            grids = {}
            for modality_name in self.temporal_encoders:
                grid = parts[cursor]
                cursor += 1
                observed_index = self.rasterizers[modality_name].channel_layout()["cell_observed"][0]
                grids[modality_name] = (grid, grid[:, observed_index] > 0.5)
            temporal_features = self._encode_temporal_from_grids(grids)

        coordinate_features = None
        if self.has_coordinates:
            coordinate_features = self.coordinate_encoder(parts[cursor])
            cursor += 1

        fused = self.fusion(static_features, temporal_features, coordinate_features)

        if self.has_auxiliary_labels:
            fused = torch.cat([fused, self.auxiliary_encoder(parts[cursor])], dim=-1)
            cursor += 1

        return fused, cursor

    def _static_feature_names(self, width: int) -> list[str]:
        """Names for the continuous static block, falling back to positions when none were stored."""
        names = list(getattr(self, "static_feature_names", None) or [])
        if len(names) == width:
            return names
        return [f"static_{index}" for index in range(width)]

    def _coordinate_names(self, width: int) -> list[str]:
        """Names for the coordinate block, falling back to positions when none were stored."""
        names = list(getattr(self, "coord_names", None) or [])
        if len(names) == width:
            return names
        return [f"coord_{index}" for index in range(width)]

    def _modality_column_names(self, modality_name: str, width: int) -> list[str]:
        """Band names for one modality, falling back to positions when none were stored."""
        stored = (getattr(self, "modality_column_names", None) or {}).get(modality_name)
        names = list(stored or [])
        if len(names) == width:
            return names
        return [f"{modality_name}_{index}" for index in range(width)]
