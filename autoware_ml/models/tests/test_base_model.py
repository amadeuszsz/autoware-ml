# Copyright 2026 TIER IV, Inc.
#
# Licensed under the Apache License, Version 2.0 (the "License");
# you may not use this file except in compliance with the License.
# You may obtain a copy of the License at
#
#     http://www.apache.org/licenses/LICENSE-2.0
#
# Unless required by applicable law or agreed to in writing, software
# distributed under the License is distributed on an "AS IS" BASIS,
# WITHOUT WARRANTIES OR CONDITIONS OF ANY KIND, either express or implied.
# See the License for the specific language governing permissions and
# limitations under the License.

"""Unit tests for the step and export contract of ``ModuleBaseModel``."""

from __future__ import annotations

from collections.abc import Mapping
from types import SimpleNamespace
from typing import Any, ClassVar

import lightning as L
import numpy as np
import pytest
import torch

from autoware_ml.anchors.base import AnchorRecipe
from autoware_ml.dataclasses.batch.sample_batch import ModelGTBatch
from autoware_ml.dataclasses.geometry.point_clouds import PointCloudGTBatch
from autoware_ml.dataclasses.models.model_batch_inputs import ModelBatchInputs
from autoware_ml.datamodule.data_module import DataModule
from autoware_ml.datamodule.streaming_data_module import StreamingDataModule
from autoware_ml.models.anchored import DataAnchored, anchor_tensor
from autoware_ml.models.module_base_model import LogDictConfigs, ModuleBaseModel
from autoware_ml.preprocessing.data_preprocessor import DataPreprocessor
from autoware_ml.types.dataset import SplitType
from autoware_ml.utils.checkpoints import load_matching_weights


class _PointSumModel(ModuleBaseModel):
    """Sum the points of the batch with one learned scale."""

    def __init__(self) -> None:
        super().__init__(
            log_dict_configs=LogDictConfigs(prog_bar=False),
            data_preprocessor=DataPreprocessor(preprocessor_modules=[]),
        )
        self.scale = torch.nn.Parameter(torch.ones(()))

    def forward(self, multi_task_batch_inputs: ModelBatchInputs) -> torch.Tensor:
        point_batch = multi_task_batch_inputs.multi_task_gt_batch.point_cloud_gt_batch
        assert point_batch is not None
        return point_batch.points.sum() * self.scale

    def compute_metrics(
        self, multi_task_batch_inputs: ModelBatchInputs, multi_task_outputs: Any
    ) -> dict[str, Any]:
        del multi_task_batch_inputs
        return {"loss": multi_task_outputs}

    def decode_outputs(self, multi_task_batch_inputs: ModelBatchInputs, outputs: Any) -> Any:
        del multi_task_batch_inputs
        return outputs


class _StreamingModel(_PointSumModel):
    """A model whose memory needs scene-contiguous batches."""

    requires_streaming: ClassVar[bool] = True


class _KeyFrameStreamingModel(_StreamingModel):
    """A streaming model whose losses skip the frames without annotations."""

    skips_unsupervised_frames: ClassVar[bool] = True


class _ForeignDataModule(L.LightningDataModule):
    """A Lightning datamodule from outside the framework that claims to stream."""

    streaming = True


def _without_sources(datamodule_type: type[DataModule]) -> DataModule:
    """An instance of a framework datamodule built without sources."""
    datamodule = datamodule_type.__new__(datamodule_type)
    datamodule.sources = {}
    return datamodule


def _serving_non_key_frames(*splits: SplitType) -> StreamingDataModule:
    """A streaming datamodule whose database serves the frames between key frames to splits."""
    datamodule = _without_sources(StreamingDataModule)
    database = SimpleNamespace(database_hash="streamed", serves_non_key_frames=True)
    source = SimpleNamespace(
        database=database, dataset=lambda split: object() if split in splits else None
    )
    datamodule.sources = {"streamed": source}
    return datamodule


def _attach_trainer(model: ModuleBaseModel, datamodule: object | None) -> None:
    """Attach a stand-in trainer carrying the given datamodule."""
    model.trainer = SimpleNamespace(datamodule=datamodule)


def _batch_inputs() -> ModelBatchInputs:
    points = PointCloudGTBatch(
        points=torch.ones(3, 4),
        batch_indices=torch.tensor([0, 0, 1], dtype=torch.int32),
        batch_size=2,
        timestamp_difference_dim=-1,
    )
    return ModelBatchInputs.from_gt_batch(
        ModelGTBatch(
            point_cloud_gt_batch=points,
            detection3d_gt_batch=None,
            segmentation3d_gt_batch=None,
            image_gt_batch=None,
            padding_mask=torch.zeros(2, dtype=torch.bool),
        )
    )


def test_step_runs_forward_on_the_batch_and_logs_the_sample_count() -> None:
    model = _PointSumModel()
    logged: dict[str, Any] = {}
    model.log_dict = lambda values, batch_size, **kwargs: logged.update(batch_size=batch_size)

    loss = model.training_step(_batch_inputs(), batch_idx=0)

    assert float(loss) == 12.0
    assert logged["batch_size"] == 2


def test_the_logged_batch_size_leaves_out_the_padding_samples() -> None:
    """
    Input: the two-sample batch with its second sample flagged as padding.
    Expected: a padding sample only keeps the ranks in step, so the step logs one sample.
    Check: the batch size handed to the logger.
    """
    model = _PointSumModel()
    logged: dict[str, Any] = {}
    model.log_dict = lambda values, batch_size, **kwargs: logged.update(batch_size=batch_size)
    batch = _batch_inputs()
    gt_batch = batch.multi_task_gt_batch._replace(padding_mask=torch.tensor([False, True]))

    model.training_step(ModelBatchInputs.from_gt_batch(gt_batch), batch_idx=0)

    assert logged["batch_size"] == 1


def test_model_without_an_export_fails_loudly() -> None:
    with pytest.raises(NotImplementedError, match="build_export_spec"):
        _PointSumModel().build_export_specs(_batch_inputs())


def test_setup_accepts_a_streaming_datamodule_for_a_streaming_model() -> None:
    """
    Input: a streaming model set up with a StreamingDataModule.
    Expected: the StreamingDataModule serves the frames of every scene in time order to each
    batch position, which is all the memory of the model needs.
    Check: ``setup`` returns without raising.
    """
    model = _StreamingModel()
    _attach_trainer(model, _without_sources(StreamingDataModule))

    model.setup("fit")


@pytest.mark.parametrize(
    ("datamodule", "found"),
    [
        (_without_sources(DataModule), "DataModule"),
        (_ForeignDataModule(), "_ForeignDataModule"),
        (None, "no datamodule"),
    ],
    ids=["plain-datamodule", "foreign-datamodule", "bare-dataloaders"],
)
def test_setup_rejects_a_streaming_model_without_a_streaming_datamodule(
    datamodule: object | None, found: str
) -> None:
    """
    Input: a streaming model set up with the plain DataModule, with an outside Lightning
    datamodule that sets ``streaming = True``, and without a datamodule.
    Expected: ``setup`` refuses all three before any batch runs: only the StreamingDataModule
    type serves scene-contiguous frames, an attribute does not count.
    Check: a ValueError asking for a StreamingDataModule and naming what the trainer runs with.
    """
    model = _StreamingModel()
    _attach_trainer(model, datamodule)

    with pytest.raises(ValueError, match=f"use a StreamingDataModule, got {found}"):
        model.setup("fit")


def test_setup_takes_frames_between_key_frames_only_for_a_model_that_skips_them() -> None:
    """
    Input: a streaming datamodule serving the frames between key frames, set up with a model
    learning from every frame and with one whose losses skip the unsupervised frames.
    Expected: the frames carry no annotations, so only the second model fits on them. The first
    one still predicts, which computes no loss, and tests on a split serving key frames only.
    Check: a ValueError for the first model, every other setup passes.
    """
    model = _StreamingModel()
    _attach_trainer(model, _serving_non_key_frames(SplitType.TRAIN, SplitType.PREDICT))
    with pytest.raises(ValueError, match="learns from every frame"):
        model.setup("fit")
    model.setup("predict")
    model.setup("test")

    model = _KeyFrameStreamingModel()
    _attach_trainer(model, _serving_non_key_frames(SplitType.TRAIN))
    model.setup("fit")


def test_setup_ignores_the_datamodule_for_a_model_without_memory() -> None:
    """
    Input: a model without memory set up without a datamodule.
    Expected: only a model that sets ``requires_streaming`` needs a streaming datamodule, so the
    check is skipped.
    Check: ``setup`` returns without raising.
    """
    model = _PointSumModel()
    _attach_trainer(model, None)

    model.setup("fit")


class _Offsets(DataAnchored):
    """Module holding three data-derived offsets."""

    anchor_names = ("offsets",)

    def __init__(self, anchor_recipe: AnchorRecipe) -> None:
        super().__init__(anchor_recipe)
        self.register_buffer("offsets", torch.zeros(3))

    def load_anchors(self, arrays: Mapping[str, np.ndarray]) -> None:
        self.offsets.copy_(anchor_tensor(arrays, "anchors", (3,)))


class _OffsetsRecipe(AnchorRecipe):
    """Recipe of the offsets that counts its builds."""

    name = "offsets"
    task_types = ()

    def __init__(self, cache_path: str) -> None:
        super().__init__(cache_path)
        self.builds = 0

    def hash_repr(self) -> str:
        return "_OffsetsRecipe()"

    def build(self, split: Any) -> dict[str, np.ndarray]:
        self.builds += 1
        return {"anchors": np.arange(3.0)}


class _AnchoredModel(_PointSumModel):
    """A model with one module whose anchors come from the training split."""

    def __init__(self, cache_path: str) -> None:
        super().__init__()
        self.offsets = _Offsets(_OffsetsRecipe(cache_path))


def _attach_split(model: ModuleBaseModel) -> None:
    """Attach a stand-in trainer whose DataModule serves a fixed training split."""
    datamodule = _without_sources(DataModule)
    datamodule.training_split = lambda: SimpleNamespace(fingerprint=lambda task_types: "db")
    _attach_trainer(model, datamodule)


def test_a_model_trained_from_scratch_builds_its_anchors_once_and_fills_them(tmp_path) -> None:
    """
    Input: a model whose module lacks anchors, prepared and configured twice like two runs.
    Expected: the first preparation builds the anchors into the cache, every configuration
      fills the module from there, a filled module needs nothing more.
    Check: one build, the offsets of the recipe, the module marked ready.
    """
    first, second = _AnchoredModel(str(tmp_path)), _AnchoredModel(str(tmp_path))
    for model in (first, second):
        _attach_split(model)
        model.prepare_data()
        model.configure_model()
        model.configure_model()

    assert first.offsets.anchor_recipe.builds == 1
    assert second.offsets.anchor_recipe.builds == 0
    torch.testing.assert_close(second.offsets.offsets, torch.arange(3.0))
    assert bool(second.offsets.anchors_ready)


def test_a_model_from_weights_reads_no_anchor_cache(tmp_path) -> None:
    """
    Input: a model whose module took its anchors from the weights of another one.
    Expected: preparation and configuration leave the anchors alone and need no datamodule.
    Check: no build, no cache file, the weights' offsets kept.
    """
    trained = _AnchoredModel(str(tmp_path))
    trained.offsets.initialize_anchors({"anchors": np.full(3, 7.0)})
    model = _AnchoredModel(str(tmp_path))
    model.load_state_dict(trained.state_dict())
    _attach_trainer(model, None)

    model.prepare_data()
    model.configure_model()

    assert model.offsets.anchor_recipe.builds == 0
    assert not list(tmp_path.iterdir())
    torch.testing.assert_close(model.offsets.offsets, torch.full((3,), 7.0))


@pytest.mark.parametrize("left_out", ["offsets.offsets", "offsets.anchors_ready"])
def test_the_anchors_and_their_ready_flag_load_together(tmp_path, left_out: str) -> None:
    """
    Input: the weights of an anchored model without its anchors, or without their ready flag.
    Expected: the flag would vouch for anchors that did not load, or loaded anchors would be
      rebuilt from the cache, so the load is refused.
    Check: ValueError naming the missing key.
    """
    trained = _AnchoredModel(str(tmp_path))
    trained.offsets.initialize_anchors({"anchors": np.full(3, 7.0)})
    weights = {key: value for key, value in trained.state_dict().items() if key != left_out}

    with pytest.raises(ValueError, match=left_out):
        _AnchoredModel(str(tmp_path)).load_state_dict(weights, strict=False)


def test_weights_with_all_or_none_of_the_anchor_state_load(tmp_path) -> None:
    """
    Input: the full weights of an anchored model, and its weights without the anchored module.
    Expected: both load, the first with ready anchors, the second leaves the anchors pending.
    Check: the ready flags and the offsets.
    """
    trained = _AnchoredModel(str(tmp_path))
    trained.offsets.initialize_anchors({"anchors": np.full(3, 7.0)})
    full, headless = _AnchoredModel(str(tmp_path)), _AnchoredModel(str(tmp_path))

    full.load_state_dict(trained.state_dict())
    headless.load_state_dict({"scale": trained.scale.detach()}, strict=False)

    assert bool(full.offsets.anchors_ready)
    torch.testing.assert_close(full.offsets.offsets, torch.full((3,), 7.0))
    assert not bool(headless.offsets.anchors_ready)


def test_anchors_skipped_for_their_shape_refuse_the_load(tmp_path) -> None:
    """
    Input: weights whose ready anchors have another shape, loaded skipping mismatched shapes.
    Expected: the skip drops the anchors but keeps their ready flag, so the load is refused.
    Check: ValueError naming the anchors.
    """
    weights = _AnchoredModel(str(tmp_path)).state_dict()
    weights["offsets.offsets"] = torch.zeros(4)
    weights["offsets.anchors_ready"] = torch.tensor(True)
    path = tmp_path / "weights.ckpt"
    torch.save({"state_dict": weights}, path)

    with pytest.raises(ValueError, match="offsets.offsets"):
        load_matching_weights(_AnchoredModel(str(tmp_path)), path, skip_mismatched_shapes=True)
