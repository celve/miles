from __future__ import annotations

import random
from types import SimpleNamespace
from unittest.mock import MagicMock

import numpy as np
import pytest
import torch
from hypothesis import HealthCheck, given, settings
from hypothesis import strategies as st
from tests.fast.ray.rollout.conftest import make_args, make_rollout_config, make_sample, make_samples_grouped
from tests.fast.train_parallel_config_utils import make_train_parallel_config
from tests.fast.utils.output_store.test_plan import ALL, INDEXER, MASK, R3, fake_store_refs, response

from miles.backends.training_utils.data import context_parallel
from miles.backends.training_utils.data import rollout as data_rollout
from miles.backends.training_utils.data.multimodal import INKLING_IMAGE_SENTINEL_ID, KIMI_VL_MEDIA_TOKEN_ID
from miles.backends.training_utils.data.rollout import DataIterator
from miles.ray.rollout import train_data_conversion
from miles.ray.rollout.train_data_conversion import (
    ROLLOUT_DATA_VALUE_SPEC,
    _post_process_rewards,
    can_precompute_dp_schedule,
    convert_samples_to_train_data,
    split_train_data_by_dp,
    split_train_data_by_dp_raw,
    split_train_data_by_dp_scheduled_raw,
)
from miles.utils.object_store import RayObjectStore
from miles.utils.output_store.plan import StorePlan, StorePlanError
from miles.utils.sampling_mask import RolloutSamplingMask
from miles.utils.types import Sample, WeightVersionSpan, WeightVersionsPerCall


# ----------------------------- convert_samples_to_train_data -----------------------------


def _store_sample(index: int, *, requested=ALL) -> Sample:
    """2 prompt and 4 output tokens, whose replay arrays are in the output store."""
    sample = make_sample(index=index, tokens=list(range(6)), rollout_log_probs=[-0.1] * 4)
    sample.rollout_store_plan = response(f"k{index}", prompt=2, output=4, requested=requested)
    return sample


class TestConvertSamplesToTrainData:
    def test_disabled_checker_leaves_custom_converter_output_untouched(self) -> None:
        """An unaudited converter does not need to supply witness identity columns."""
        converted = {"custom_payload": [1, 2]}

        out = convert_samples_to_train_data(
            make_rollout_config(enable_sample_ownership_checker=False),
            [make_sample()],
            metadata={},
            custom_convert_samples_to_train_data_func=lambda args, samples: converted,
            custom_reward_post_process_func=None,
        )

        assert out is converted
        assert out == {"custom_payload": [1, 2]}

    def test_repeated_unstamped_sample_index_remains_duplicate_identity(self):
        """Unstamped duplicate indices remain visible as duplicate rows."""
        args = make_args(advantage_estimator="grpo", rewards_normalization=False, enable_sample_ownership_checker=True)
        samples = [make_sample(index=7), make_sample(index=7), make_sample(index=8)]

        out = convert_samples_to_train_data(
            args,
            samples,
            metadata={},
            custom_convert_samples_to_train_data_func=None,
            custom_reward_post_process_func=None,
        )

        assert out["lineage_source_sample_indices"] == [7, 7, 8]
        assert out["lineage_output_indices"] == [0, 0, 0]
        assert out["lineage_output_counts"] == [1, 1, 1]

    def test_default_path_produces_required_keys(self):
        args = make_args(advantage_estimator="grpo", rewards_normalization=False)
        samples = make_samples_grouped(n_groups=2, group_size=4)
        out = convert_samples_to_train_data(
            args,
            samples,
            metadata={},
            custom_convert_samples_to_train_data_func=None,
            custom_reward_post_process_func=None,
        )
        for key in (
            "tokens",
            "response_lengths",
            "rewards",
            "raw_reward",
            "truncated",
            "sample_indices",
            "loss_masks",
        ):
            assert key in out, f"missing required key {key}"
        assert len(out["tokens"]) == len(samples)

    def test_loss_mask_none_filled_with_ones(self):
        args = make_args(rewards_normalization=False)
        s = make_sample(response_length=5)
        s.loss_mask = None
        out = convert_samples_to_train_data(
            args,
            [s],
            metadata={},
            custom_convert_samples_to_train_data_func=None,
            custom_reward_post_process_func=None,
        )
        assert out["loss_masks"][0] == [1] * 5

    def test_remove_sample_zeroes_loss_mask(self):
        args = make_args(rewards_normalization=False)
        s = make_sample(response_length=4)
        s.loss_mask = [1, 1, 1, 1]
        s.remove_sample = True
        out = convert_samples_to_train_data(
            args,
            [s],
            metadata={},
            custom_convert_samples_to_train_data_func=None,
            custom_reward_post_process_func=None,
        )
        assert out["loss_masks"][0] == [0, 0, 0, 0]

    def test_loss_mask_length_mismatch_asserts(self):
        args = make_args(rewards_normalization=False)
        s = make_sample(response_length=4)
        s.loss_mask = [1, 1]  # wrong length
        with pytest.raises(AssertionError):
            convert_samples_to_train_data(
                args,
                [s],
                metadata={},
                custom_convert_samples_to_train_data_func=None,
                custom_reward_post_process_func=None,
            )

    def test_truncated_status_marked(self):
        args = make_args(rewards_normalization=False)
        s = make_sample(status=Sample.Status.TRUNCATED)
        out = convert_samples_to_train_data(
            args,
            [s],
            metadata={},
            custom_convert_samples_to_train_data_func=None,
            custom_reward_post_process_func=None,
        )
        assert out["truncated"][0] == 1

    def test_optional_field_rollout_log_probs_passed_through(self):
        args = make_args(rewards_normalization=False)
        s = make_sample()
        s.rollout_log_probs = [-0.1, -0.2, -0.3, -0.4]
        out = convert_samples_to_train_data(
            args,
            [s],
            metadata={},
            custom_convert_samples_to_train_data_func=None,
            custom_reward_post_process_func=None,
        )
        assert out["rollout_log_probs"][0] == [-0.1, -0.2, -0.3, -0.4]

    def test_sampling_mask_passed_through(self):
        args = make_args(rewards_normalization=False)
        s = make_sample()
        s.rollout_sampling_mask = RolloutSamplingMask(
            ids=[0, 7, 1, 8, 2, 9, 3, 10],
            offsets=[0, 2, 4, 6, 8],
        )
        out = convert_samples_to_train_data(
            args,
            [s],
            metadata={},
            custom_convert_samples_to_train_data_func=None,
            custom_reward_post_process_func=None,
        )
        assert out["rollout_sampling_mask_ids"][0].tolist() == [0, 7, 1, 8, 2, 9, 3, 10]
        assert out["rollout_sampling_mask_offsets"][0].tolist() == [0, 2, 4, 6, 8]

    def test_sampling_mask_requires_complete_batch(self):
        args = make_args(rewards_normalization=False)
        captured = make_sample(index=8)
        captured.rollout_sampling_mask = RolloutSamplingMask(
            ids=[0, 7, 1, 8, 2, 9, 3, 10],
            offsets=[0, 2, 4, 6, 8],
        )

        with pytest.raises(
            ValueError,
            match=r"must be present for every training sample.*sample_index=9",
        ):
            convert_samples_to_train_data(
                args,
                [captured, make_sample(index=9)],
                metadata={},
                custom_convert_samples_to_train_data_func=None,
                custom_reward_post_process_func=None,
            )

    def test_store_plans_become_a_column_that_satisfies_the_replay_flags(self):
        args = make_args(rewards_normalization=False, use_rollout_routing_replay=True, use_rollout_indexer_replay=True)
        samples = [_store_sample(0), _store_sample(1)]

        out = convert_samples_to_train_data(args, samples, {}, None, None)

        assert out["rollout_store_plan"] == [sample.rollout_store_plan.to_dict() for sample in samples]
        assert not {"rollout_routed_experts", "rollout_indexer_topk", "rollout_sampling_mask_ids"} & out.keys()

    @pytest.mark.parametrize("missing", [0, 1])
    def test_store_plans_are_all_or_none(self, missing: int):
        samples = [make_sample(index=i) if i == missing else _store_sample(i) for i in range(2)]
        with pytest.raises(StorePlanError, match=rf"missing at position={missing}, sample_index={missing}"):
            convert_samples_to_train_data(make_args(rewards_normalization=False), samples, {}, None, None)
        inline = [make_sample(index=0), make_sample(index=1)]
        assert "rollout_store_plan" not in convert_samples_to_train_data(
            make_args(rewards_normalization=False), inline, {}, None, None
        )

    def test_store_plans_must_match_their_samples(self):
        short = _store_sample(1)
        short.rollout_store_plan = response("k1", prompt=2, output=3)
        with pytest.raises(StorePlanError, match="routed_experts has 4 rows; expected 5"):
            convert_samples_to_train_data(
                make_args(rewards_normalization=False), [_store_sample(0), short], {}, None, None
            )

    def test_store_plans_must_share_their_fields(self):
        samples = [_store_sample(0), _store_sample(1, requested={MASK})]
        with pytest.raises(StorePlanError, match="must have the same fields"):
            convert_samples_to_train_data(make_args(rewards_normalization=False), samples, {}, None, None)

    @pytest.mark.parametrize(
        ("flag", "field"), [("use_rollout_routing_replay", R3), ("use_rollout_indexer_replay", INDEXER)]
    )
    def test_a_replay_flag_requires_its_field_in_the_store_plans(self, flag: str, field: str):
        args = make_args(rewards_normalization=False, **{flag: True})
        with pytest.raises(StorePlanError, match=rf"--{flag.replace('_', '-')} is set .* no {field}"):
            convert_samples_to_train_data(args, [_store_sample(0, requested=ALL - {field})], {}, None, None)

    def test_support_mode_store_plans_leave_the_candidates_to_the_trainer(self):
        args = make_args(
            rewards_normalization=False,
            rollout_top_logprobs_num=2,
            rollout_sampling_logprobs_mode="support",
            ci_test=True,
        )

        out = convert_samples_to_train_data(args, [_store_sample(0)], {}, None, None)

        assert out["rollout_log_probs"] == [[-0.1] * 4]
        assert not {"rollout_topk_token_ids", "rollout_topk_log_probs", "rollout_topk_lengths"} & out.keys()
        # The trainer does not produce the sampled log-probs, and builds the candidates from the stored mask.
        without_log_probs = _store_sample(0)
        without_log_probs.rollout_log_probs = None
        with pytest.raises(ValueError, match="requires rollout_log_probs"):
            convert_samples_to_train_data(args, [without_log_probs], {}, None, None)
        with pytest.raises(StorePlanError, match="stored sampling mask"):
            convert_samples_to_train_data(args, [_store_sample(0, requested={R3})], {}, None, None)

    def test_selected_mode_store_plans_still_need_the_inline_candidates(self):
        args = make_args(rewards_normalization=False, rollout_top_logprobs_num=2)
        with pytest.raises(ValueError, match="requires rollout_topk_token_ids"):
            convert_samples_to_train_data(args, [_store_sample(0)], {}, None, None)

    def test_optional_field_round_number_from_metadata(self):
        args = make_args(rewards_normalization=False)
        s = make_sample()
        s.metadata = {"round_number": 7}
        out = convert_samples_to_train_data(
            args,
            [s],
            metadata={},
            custom_convert_samples_to_train_data_func=None,
            custom_reward_post_process_func=None,
        )
        assert out["round_number"][0] == 7

    def test_optional_field_raw_reward_overridden_from_metadata(self):
        args = make_args(rewards_normalization=False)
        s = make_sample(reward=1.0)
        s.metadata = {"raw_reward": 9.0}
        out = convert_samples_to_train_data(
            args,
            [s],
            metadata={},
            custom_convert_samples_to_train_data_func=None,
            custom_reward_post_process_func=None,
        )
        assert out["raw_reward"][0] == 9.0

    def test_rollout_ids_default_to_sample_index(self):
        args = make_args(rewards_normalization=False)
        samples = [make_sample(index=i) for i in range(3)]
        out = convert_samples_to_train_data(
            args,
            samples,
            metadata={},
            custom_convert_samples_to_train_data_func=None,
            custom_reward_post_process_func=None,
        )
        assert out["rollout_ids"] == [0, 1, 2]

    def test_rollout_ids_use_explicit_rollout_id_when_set(self):
        args = make_args(rewards_normalization=False)
        samples = [make_sample(index=i) for i in range(4)]
        # two compact siblings sharing one rollout execution
        samples[1].rollout_id = samples[2].rollout_id = 1
        out = convert_samples_to_train_data(
            args,
            samples,
            metadata={},
            custom_convert_samples_to_train_data_func=None,
            custom_reward_post_process_func=None,
        )
        assert out["rollout_ids"] == [0, 1, 1, 3]

    def test_weight_versions_are_converted_to_serializable_dicts(self):
        """Weight version spans cross the object-store boundary as plain msgpack values."""
        args = make_args(rewards_normalization=False)
        sample = make_sample()
        sample.weight_versions = [
            WeightVersionsPerCall(spans=[WeightVersionSpan(version="v1", abs_start=2, abs_end=4)])
        ]

        out = convert_samples_to_train_data(
            args,
            [sample],
            metadata={},
            custom_convert_samples_to_train_data_func=None,
            custom_reward_post_process_func=None,
        )

        assert out["weight_versions"] == [
            [
                {
                    "spans": [{"version": "v1", "abs_start": 2, "abs_end": 4}],
                    "prefill_spans": [],
                    "output_start": None,
                    "prompt_tokens": None,
                }
            ]
        ]

    def test_weight_version_serialization_preserves_empty_samples_and_calls(self):
        """A sample without calls and a call without spans keep their slots, so rows and turn counts stay aligned."""
        args = make_args(rewards_normalization=False)
        stamped = make_sample(index=0)
        stamped.weight_versions = [
            WeightVersionsPerCall(spans=[]),
            WeightVersionsPerCall(spans=[WeightVersionSpan(version="v1", abs_start=2, abs_end=4)]),
        ]
        unstamped = make_sample(index=1)
        unstamped.weight_versions = []

        out = convert_samples_to_train_data(
            args,
            [stamped, unstamped],
            metadata={},
            custom_convert_samples_to_train_data_func=None,
            custom_reward_post_process_func=None,
        )

        assert out["weight_versions"] == [
            [
                {"spans": [], "prefill_spans": [], "output_start": None, "prompt_tokens": None},
                {
                    "spans": [{"version": "v1", "abs_start": 2, "abs_end": 4}],
                    "prefill_spans": [],
                    "output_start": None,
                    "prompt_tokens": None,
                },
            ],
            [],
        ]

    def test_weight_version_serialization_round_trips_prefill_spans(self):
        """Prompt KV spans reach the train data as plain values and read back as the same typed calls."""
        args = make_args(rewards_normalization=False)
        sample = make_sample()
        sample.weight_versions = [
            WeightVersionsPerCall(
                spans=[WeightVersionSpan(version="2", abs_start=2, abs_end=4)],
                prefill_spans=[
                    WeightVersionSpan(version="1", abs_start=0, abs_end=1),
                    WeightVersionSpan(version="2", abs_start=1, abs_end=2),
                ],
                output_start=2,
            )
        ]

        out = convert_samples_to_train_data(
            args,
            [sample],
            metadata={},
            custom_convert_samples_to_train_data_func=None,
            custom_reward_post_process_func=None,
        )

        assert out["weight_versions"] == [
            [
                {
                    "spans": [{"version": "2", "abs_start": 2, "abs_end": 4}],
                    "prefill_spans": [
                        {"version": "1", "abs_start": 0, "abs_end": 1},
                        {"version": "2", "abs_start": 1, "abs_end": 2},
                    ],
                    "output_start": 2,
                    "prompt_tokens": None,
                }
            ]
        ]
        assert [WeightVersionsPerCall.from_dict(call) for call in out["weight_versions"][0]] == sample.weight_versions

    def test_dynamic_global_batch_size_metadata_must_match(self):
        args = make_args(use_dynamic_global_batch_size=True, rewards_normalization=False)
        with pytest.raises(AssertionError):
            convert_samples_to_train_data(
                args,
                [make_sample()],
                metadata={},
                custom_convert_samples_to_train_data_func=None,
                custom_reward_post_process_func=None,
            )

    def test_dynamic_global_batch_size_metadata_passed_through(self):
        args = make_args(use_dynamic_global_batch_size=True, rewards_normalization=False)
        out = convert_samples_to_train_data(
            args,
            [make_sample()],
            metadata={"dynamic_global_batch_size": 16},
            custom_convert_samples_to_train_data_func=None,
            custom_reward_post_process_func=None,
        )
        assert out["dynamic_global_batch_size"] == 16


# ----------------------------- _post_process_rewards -----------------------------


class TestPostProcessRewards:
    def test_ppo_path_returns_raw_rewards_unchanged(self):
        args = make_args(advantage_estimator="ppo", rewards_normalization=True)
        samples = make_samples_grouped(2, 4, rewards=[1.0, 2.0, 3.0, 4.0, 5.0, 6.0, 7.0, 8.0])
        raw, processed = _post_process_rewards(args, samples, custom_reward_post_process_func=None)
        assert raw == processed

    def test_grpo_normalizes_each_group_to_zero_mean(self):
        args = make_args(
            advantage_estimator="grpo",
            rewards_normalization=True,
            grpo_std_normalization=False,
            n_samples_per_prompt=4,
            rollout_batch_size=2,
        )
        samples = make_samples_grouped(2, 4, rewards=[1.0, 2.0, 3.0, 4.0, 10.0, 20.0, 30.0, 40.0])
        _, processed = _post_process_rewards(args, samples, custom_reward_post_process_func=None)
        # group means: 2.5 and 25.0 → centered values
        g1 = processed[:4]
        g2 = processed[4:]
        assert abs(sum(g1) / 4) < 1e-5
        assert abs(sum(g2) / 4) < 1e-5

    def test_grpo_with_std_normalization_unit_variance(self):
        args = make_args(
            advantage_estimator="grpo",
            rewards_normalization=True,
            grpo_std_normalization=True,
            n_samples_per_prompt=4,
            rollout_batch_size=1,
        )
        samples = make_samples_grouped(1, 4, rewards=[1.0, 2.0, 3.0, 4.0])
        _, processed = _post_process_rewards(args, samples, custom_reward_post_process_func=None)
        # Unit std with epsilon — torch.std uses N-1 by default; centered
        # values have std exactly 1.0 after dividing by their own std.
        import numpy as np

        assert abs(np.std(processed, ddof=1) - 1.0) < 1e-4

    def test_gspo_uses_grpo_normalization_path(self):
        args = make_args(
            advantage_estimator="gspo",
            rewards_normalization=True,
            grpo_std_normalization=False,
            n_samples_per_prompt=4,
            rollout_batch_size=1,
        )
        samples = make_samples_grouped(1, 4, rewards=[1.0, 2.0, 3.0, 4.0])
        _, processed = _post_process_rewards(args, samples, custom_reward_post_process_func=None)
        assert abs(sum(processed) / 4) < 1e-5

    def test_reinforce_plus_plus_baseline_only_zero_mean_no_std(self):
        args = make_args(
            advantage_estimator="reinforce_plus_plus_baseline",
            rewards_normalization=True,
            grpo_std_normalization=True,  # should be IGNORED on this path
            n_samples_per_prompt=4,
            rollout_batch_size=1,
        )
        samples = make_samples_grouped(1, 4, rewards=[1.0, 2.0, 3.0, 4.0])
        _, processed = _post_process_rewards(args, samples, custom_reward_post_process_func=None)
        # Mean is zero (centering happens) and std is the std of the centered
        # input (no normalization applied) — pin this exactly so a regression
        # that re-enabled the std division is caught.
        assert abs(sum(processed) / 4) < 1e-5
        import numpy as np

        expected_std = float(np.std([-1.5, -0.5, 0.5, 1.5]))
        assert abs(np.std(processed) - expected_std) < 1e-5

    def test_irregular_group_size_uses_explicit_group_index(self):
        """Explicit group identity keeps an irregularly sized group together."""
        args = make_args(
            advantage_estimator="grpo",
            rewards_normalization=True,
            grpo_std_normalization=False,
            n_samples_per_prompt=8,
            rollout_batch_size=2,
        )
        # rewards length 4 — does not match 8 * 2 = 16; trigger view branch
        samples = make_samples_grouped(1, 4, rewards=[2.0, 4.0, 6.0, 8.0])
        _, processed = _post_process_rewards(args, samples, custom_reward_post_process_func=None)
        # mean is 5.0, after centering: -3, -1, 1, 3
        assert abs(sum(processed)) < 1e-5

    def test_grpo_normalizes_unique_rollouts_with_unequal_fanout(self):
        args = make_args(
            advantage_estimator="grpo",
            rewards_normalization=True,
            grpo_std_normalization=False,
            n_samples_per_prompt=2,
            rollout_batch_size=2,
        )
        samples = [
            make_sample(group_index=0, index=0, rollout_id=10, reward=0.0),
            make_sample(group_index=0, index=1, rollout_id=11, reward=1.0),
            make_sample(group_index=0, index=1, rollout_id=11, reward=1.0),
            make_sample(group_index=0, index=1, rollout_id=11, reward=1.0),
            make_sample(group_index=1, index=2, rollout_id=20, reward=2.0),
            make_sample(group_index=1, index=2, rollout_id=20, reward=2.0),
            make_sample(group_index=1, index=3, rollout_id=21, reward=4.0),
        ]

        raw, processed = _post_process_rewards(args, samples, custom_reward_post_process_func=None)

        assert raw == [0.0, 1.0, 1.0, 1.0, 2.0, 2.0, 4.0]
        assert processed == pytest.approx([-0.5, 0.5, 0.5, 0.5, -1.0, -1.0, 1.0])

    def test_grpo_broadcasts_std_normalized_rollout_advantage(self):
        args = make_args(
            advantage_estimator="grpo",
            rewards_normalization=True,
            grpo_std_normalization=True,
            n_samples_per_prompt=2,
            rollout_batch_size=1,
        )
        samples = [
            make_sample(group_index=0, index=0, rollout_id=10, reward=0.0),
            make_sample(group_index=0, index=1, rollout_id=11, reward=1.0),
            make_sample(group_index=0, index=1, rollout_id=11, reward=1.0),
        ]

        _, processed = _post_process_rewards(args, samples, custom_reward_post_process_func=None)

        assert processed == pytest.approx([-(2**-0.5), 2**-0.5, 2**-0.5], abs=1e-5)

    def test_grpo_rejects_different_sibling_rewards(self):
        args = make_args(
            advantage_estimator="grpo",
            rewards_normalization=True,
            grpo_std_normalization=False,
            n_samples_per_prompt=2,
            rollout_batch_size=1,
        )
        samples = [
            make_sample(group_index=0, index=0, rollout_id=10, reward=0.0, loss_mask=[1, 1, 1, 1]),
            make_sample(group_index=0, index=1, rollout_id=11, reward=2.0, loss_mask=[1, 0, 0, 0]),
            make_sample(group_index=0, index=1, rollout_id=11, reward=6.0, loss_mask=[1, 1, 1, 0]),
        ]

        with pytest.raises(
            ValueError,
            match=r"all samples in a rollout must share one reward; rows \[1, 2\] have rewards \[2.0, 6.0\]",
        ):
            _post_process_rewards(args, samples, custom_reward_post_process_func=None)

    def test_grpo_shared_reward_ignores_final_training_mask(self):
        args = make_args(
            advantage_estimator="grpo",
            rewards_normalization=True,
            grpo_std_normalization=False,
            n_samples_per_prompt=2,
            rollout_batch_size=1,
        )
        samples = [
            make_sample(
                group_index=0,
                index=0,
                rollout_id=10,
                reward=2.0,
                response_length=8,
                remove_sample=True,
            ),
            make_sample(group_index=0, index=0, rollout_id=10, reward=2.0, response_length=4),
            make_sample(group_index=0, index=1, rollout_id=11, reward=6.0, loss_mask=[1, 1, 0, 0]),
        ]

        train_data = convert_samples_to_train_data(
            args,
            samples,
            metadata={},
            custom_convert_samples_to_train_data_func=None,
            custom_reward_post_process_func=None,
        )

        assert train_data["raw_reward"] == [2.0, 2.0, 6.0]
        assert train_data["rewards"] == pytest.approx([-2.0, -2.0, 2.0])
        assert train_data["loss_masks"] == [[0] * 8, [1] * 4, [1, 1, 0, 0]]

    def test_grpo_shared_reward_uses_selected_reward_key(self):
        args = make_args(
            advantage_estimator="grpo",
            rewards_normalization=True,
            grpo_std_normalization=False,
            reward_key="score",
            n_samples_per_prompt=2,
            rollout_batch_size=1,
        )
        samples = [
            make_sample(group_index=0, index=0, rollout_id=10, reward={"score": 2.0, "detail": "first"}),
            make_sample(group_index=0, index=0, rollout_id=10, reward={"score": 2.0, "detail": "second"}),
            make_sample(group_index=0, index=1, rollout_id=11, reward={"score": 6.0}),
        ]

        raw, processed = _post_process_rewards(args, samples, custom_reward_post_process_func=None)

        assert raw == [2.0, 2.0, 6.0]
        assert processed == pytest.approx([-2.0, -2.0, 2.0])

    def test_prompt_group_sizes_override_reused_group_index(self):
        args = make_args(advantage_estimator="grpo", rewards_normalization=True)
        samples = [
            make_sample(group_index=0, rollout_id=10, reward=0.0),
            make_sample(group_index=0, rollout_id=11, reward=2.0),
            make_sample(group_index=0, rollout_id=20, reward=10.0),
            make_sample(group_index=0, rollout_id=21, reward=14.0),
        ]

        _, processed = _post_process_rewards(
            args,
            samples,
            custom_reward_post_process_func=None,
            prompt_group_sizes=[2, 2],
        )

        assert processed == pytest.approx([-1.0, 1.0, -2.0, 2.0])

    def test_noncontiguous_group_indices_share_reward_group(self):
        args = make_args(advantage_estimator="grpo", rewards_normalization=True)
        samples = [
            make_sample(group_index=0, rollout_id=10, reward=0.0),
            make_sample(group_index=1, rollout_id=20, reward=10.0),
            make_sample(group_index=0, rollout_id=11, reward=2.0),
            make_sample(group_index=1, rollout_id=21, reward=14.0),
        ]

        _, processed = _post_process_rewards(args, samples, custom_reward_post_process_func=None)

        assert processed == pytest.approx([-1.0, -2.0, 1.0, 2.0])

    @pytest.mark.parametrize(
        ("rewards", "expected"),
        [
            ([0.0, 2.0, 10.0, 14.0], [-1.0, 1.0, -2.0, 2.0]),
            ([0.0, 2.0, 4.0], [-2.0, 0.0, 2.0]),
        ],
    )
    def test_missing_group_indices_use_legacy_boundaries(self, rewards, expected):
        args = make_args(
            advantage_estimator="grpo",
            rewards_normalization=True,
            n_samples_per_prompt=2,
            rollout_batch_size=2,
        )
        samples = [
            make_sample(group_index=None, rollout_id=rollout_id, reward=reward)
            for rollout_id, reward in enumerate(rewards)
        ]

        _, processed = _post_process_rewards(args, samples, custom_reward_post_process_func=None)

        assert processed == pytest.approx(expected)

    def test_rows_without_rollout_identity_stay_distinct(self):
        args = make_args(advantage_estimator="grpo", rewards_normalization=True)
        samples = [
            make_sample(group_index=0, index=None, rollout_id=None, reward=0.0),
            make_sample(group_index=0, index=None, rollout_id=None, reward=2.0),
        ]

        _, processed = _post_process_rewards(args, samples, custom_reward_post_process_func=None)

        assert processed == pytest.approx([-1.0, 1.0])

    def test_empty_rewards_stay_empty(self):
        args = make_args(advantage_estimator="grpo", rewards_normalization=True)

        raw, processed = _post_process_rewards(args, [], custom_reward_post_process_func=None)

        assert raw == processed == []

    def test_custom_reward_post_process_short_circuits(self):
        args = make_rollout_config(advantage_estimator="grpo", rewards_normalization=True)
        sentinel = ([0.0], [1.0])
        raw, processed = _post_process_rewards(
            args, [make_sample()], custom_reward_post_process_func=lambda a, s: sentinel
        )
        assert (raw, processed) == sentinel


class TestPostProcessRewardsProperties:
    """Hypothesis-driven invariants for the GRPO normalization path.

    The point-tests above pin specific shapes; these guarantee the math holds
    across arbitrary group counts, group sizes, and reward distributions —
    catching bugs (e.g. wrong reshape axis, sign flip) that a fixed example
    might miss."""

    @settings(
        suppress_health_check=[HealthCheck.function_scoped_fixture],
        deadline=None,
        max_examples=40,
    )
    @given(
        n_groups=st.integers(min_value=1, max_value=6),
        group_size=st.integers(min_value=2, max_value=8),
        seed=st.integers(min_value=0, max_value=2**31 - 1),
    )
    def test_grpo_zero_mean_invariant(self, n_groups, group_size, seed):
        """After GRPO centering, every group's mean must be ≈ 0 regardless of
        input distribution."""
        import random

        rng = random.Random(seed)
        rewards_list = [rng.uniform(-1000, 1000) for _ in range(n_groups * group_size)]
        args = make_args(
            advantage_estimator="grpo",
            rewards_normalization=True,
            grpo_std_normalization=False,
            n_samples_per_prompt=group_size,
            rollout_batch_size=n_groups,
        )
        samples = make_samples_grouped(n_groups, group_size, rewards=rewards_list)
        _, processed = _post_process_rewards(args, samples, custom_reward_post_process_func=None)

        assert len(processed) == n_groups * group_size
        for g in range(n_groups):
            chunk = processed[g * group_size : (g + 1) * group_size]
            # Tolerance scales with magnitude; 1e-3 of mean(|input|) covers fp32 drift.
            scale = max(abs(min(rewards_list)), abs(max(rewards_list)), 1.0)
            assert abs(sum(chunk) / group_size) < 1e-3 * scale, f"group {g} mean is not zero: chunk={chunk}"

    @settings(
        suppress_health_check=[HealthCheck.function_scoped_fixture],
        deadline=None,
        max_examples=40,
    )
    @given(
        n_groups=st.integers(min_value=1, max_value=6),
        group_size=st.integers(min_value=2, max_value=8),
        seed=st.integers(min_value=0, max_value=2**31 - 1),
    )
    def test_grpo_unit_variance_invariant(self, n_groups, group_size, seed):
        """With grpo_std_normalization=True, each group's processed std → 1.

        We construct rewards whose per-group std is well above the 1e-6 epsilon
        floor; otherwise the epsilon-stabilized division produces ≈0 not ≈1."""
        import random

        import numpy as np

        rng = random.Random(seed)
        rewards_list: list[float] = []
        for _g in range(n_groups):
            base = rng.uniform(-100, 100)
            spread = rng.uniform(0.5, 50.0)  # >> epsilon
            for k in range(group_size):
                rewards_list.append(base + spread * (k - (group_size - 1) / 2))

        args = make_args(
            advantage_estimator="grpo",
            rewards_normalization=True,
            grpo_std_normalization=True,
            n_samples_per_prompt=group_size,
            rollout_batch_size=n_groups,
        )
        samples = make_samples_grouped(n_groups, group_size, rewards=rewards_list)
        _, processed = _post_process_rewards(args, samples, custom_reward_post_process_func=None)

        for g in range(n_groups):
            chunk = processed[g * group_size : (g + 1) * group_size]
            std_val = float(np.std(chunk, ddof=1))
            assert abs(std_val - 1.0) < 1e-3, f"group {g} std={std_val}, chunk={chunk}"

    @settings(
        suppress_health_check=[HealthCheck.function_scoped_fixture],
        deadline=None,
        max_examples=30,
    )
    @given(
        n=st.integers(min_value=1, max_value=32),
        seed=st.integers(min_value=0, max_value=2**31 - 1),
    )
    def test_ppo_path_is_identity(self, n, seed):
        """PPO never normalizes rewards regardless of any other flag."""
        import random

        rng = random.Random(seed)
        rewards_list = [rng.uniform(-50, 50) for _ in range(n)]
        args = make_args(
            advantage_estimator="ppo",
            rewards_normalization=True,
            grpo_std_normalization=True,
            n_samples_per_prompt=n,
            rollout_batch_size=1,
        )
        samples = make_samples_grouped(1, n, rewards=rewards_list)
        raw, processed = _post_process_rewards(args, samples, custom_reward_post_process_func=None)
        assert raw == processed == rewards_list


# ----------------------------- split_train_data_by_dp -----------------------------


class TestSplitTrainDataByDp:
    def test_strided_partition_when_balance_data_off(self):
        args = make_args(balance_data=False)
        data = {
            "tokens": [[1, 2], [3, 4, 5], [6], [7, 8, 9, 10]],
            "response_lengths": [2, 3, 1, 4],
            "rewards": [0.1, 0.2, 0.3, 0.4],
            "truncated": [0, 0, 0, 1],
            "loss_masks": [[1, 1]] * 4,
            "sample_indices": [0, 1, 2, 3],
        }
        parts = split_train_data_by_dp(
            args=args, data=data, train_parallel_config=make_train_parallel_config(dp_size=2)
        )
        # stride: dp=0 takes [0, 2], dp=1 takes [1, 3]
        assert list(parts[0]["partition"]) == [0, 2]
        assert list(parts[1]["partition"]) == [1, 3]
        assert parts[0]["tokens"] == [[1, 2], [6]]

    def test_balanced_partition_when_balance_data_on(self):
        args = make_args(balance_data=True)
        # lengths chosen to force grouping: 1 + 4 vs 2 + 3 are balanced
        data = {
            "tokens": [[1], [2, 3], [4, 5, 6], [7, 8, 9, 10]],
            "response_lengths": [1, 2, 3, 4],
            "rewards": [0, 0, 0, 0],
            "truncated": [0, 0, 0, 0],
            "loss_masks": [[1] * n for n in (1, 2, 3, 4)],
            "sample_indices": [0, 1, 2, 3],
        }
        parts = split_train_data_by_dp(
            args=args, data=data, train_parallel_config=make_train_parallel_config(dp_size=2)
        )
        sizes = [len(p["tokens"]) for p in parts]
        assert max(sizes) - min(sizes) <= 1

    def test_optional_keys_propagated_when_present(self):
        args = make_args(balance_data=False)
        data = {
            "tokens": [[1], [2]],
            "response_lengths": [1, 1],
            "rewards": [0, 0],
            "truncated": [0, 0],
            "loss_masks": [[1], [1]],
            "sample_indices": [0, 1],
            "rollout_log_probs": [[-0.1], [-0.2]],
            "round_number": [1, 2],
        }
        parts = split_train_data_by_dp(
            args=args, data=data, train_parallel_config=make_train_parallel_config(dp_size=2)
        )
        assert "rollout_log_probs" in parts[0]
        assert "round_number" in parts[0]

    def test_shared_keys_not_split(self):
        """raw_reward, total_lengths, dynamic_global_batch_size are shared, not split."""
        args = make_args(balance_data=False)
        data = {
            "tokens": [[1], [2], [3], [4]],
            "response_lengths": [1, 1, 1, 1],
            "rewards": [0, 0, 0, 0],
            "truncated": [0, 0, 0, 0],
            "loss_masks": [[1]] * 4,
            "sample_indices": [0, 1, 2, 3],
            "raw_reward": [9.0, 8.0, 7.0, 6.0],
            "dynamic_global_batch_size": 4,
        }
        parts = split_train_data_by_dp(
            args=args, data=data, train_parallel_config=make_train_parallel_config(dp_size=2)
        )
        for p in parts:
            assert p["raw_reward"] == [9.0, 8.0, 7.0, 6.0]
            assert p["dynamic_global_batch_size"] == 4

    def test_weight_versions_survive_the_object_store_with_their_prefill_spans(self, ray_local_mode: None) -> None:
        """Per-call prefill spans reach a DP shard through the store and read back as the same typed calls."""
        args = make_args(balance_data=False)
        calls = [
            WeightVersionsPerCall(
                spans=[WeightVersionSpan(version="2", abs_start=2, abs_end=4)],
                prefill_spans=[WeightVersionSpan(version="1", abs_start=0, abs_end=2)],
                output_start=2,
            ),
            WeightVersionsPerCall(
                spans=[WeightVersionSpan(version="3", abs_start=6, abs_end=7)],
                prefill_spans=[
                    WeightVersionSpan(version="1", abs_start=0, abs_end=2),
                    WeightVersionSpan(version="3", abs_start=2, abs_end=6),
                ],
                output_start=6,
            ),
        ]
        Sample(tokens=[1, 2, 3, 4, 5, 6, 7], response_length=5, weight_versions=calls).validate()
        data = {
            "tokens": [[1, 2, 3, 4, 5, 6, 7]],
            "response_lengths": [5],
            "rewards": [0],
            "truncated": [0],
            "loss_masks": [[1, 1, 0, 0, 1]],
            "sample_indices": [0],
            "weight_versions": [[call.to_dict() for call in calls]],
        }

        [shard] = split_train_data_by_dp(
            args=args, data=data, train_parallel_config=make_train_parallel_config(dp_size=1)
        )
        store = RayObjectStore(frees_objects=False)
        ref = store.put(value=shard, value_spec=ROLLOUT_DATA_VALUE_SPEC)
        with store.get(ref) as part:
            assert [WeightVersionsPerCall.from_dict(call) for call in part["weight_versions"][0]] == calls

    def test_store_plans_survive_the_object_store(self, ray_local_mode: None, monkeypatch: pytest.MonkeyPatch) -> None:
        """A converted, split and stored plan reads back as the sample's plan."""
        fake_store_refs(monkeypatch)
        samples = [_store_sample(0), _store_sample(1)]
        data = convert_samples_to_train_data(make_args(rewards_normalization=False), samples, {}, None, None)

        [shard] = split_train_data_by_dp(
            args=make_args(balance_data=False), data=data, train_parallel_config=make_train_parallel_config(dp_size=1)
        )
        store = RayObjectStore(frees_objects=False)
        stored = store.put(value=shard, value_spec=ROLLOUT_DATA_VALUE_SPEC)
        with store.get(stored) as part:
            plans = [StorePlan.from_dict(value) for value in part["rollout_store_plan"]]
        assert plans == [samples[i].rollout_store_plan for i in shard["partition"]]

    def test_partition_indices_form_a_partition(self):
        """All partition indices together cover [0, N) exactly once."""
        args = make_args(balance_data=False)
        n = 12
        data = {
            "tokens": [[i] for i in range(n)],
            "response_lengths": [1] * n,
            "rewards": [0] * n,
            "truncated": [0] * n,
            "loss_masks": [[1]] * n,
            "sample_indices": list(range(n)),
        }
        parts = split_train_data_by_dp(
            args=args, data=data, train_parallel_config=make_train_parallel_config(dp_size=4)
        )
        all_indices = sorted(i for p in parts for i in p["partition"])
        assert all_indices == list(range(n))


class TestSplitTrainDataRaw:
    def test_witness_ids_split_across_dp(self) -> None:
        tokens = [[1, 2, 3], [4, 5], [6, 7, 8, 9], [10, 11]]
        witness_ids = [
            torch.tensor([0, 0, 0]),
            torch.tensor([1, 1]),
            torch.tensor([2, 2, 2, 2]),
            torch.tensor([3, 3]),
        ]

        data = {
            "tokens": tokens,
            "seq_witness_ids": witness_ids,
            "response_lengths": [1, 1, 1, 1],
            "loss_masks": [[0, 0, 1], [0, 1], [0, 0, 0, 1], [0, 1]],
        }

        args = MagicMock()
        args.balance_data = False

        result = split_train_data_by_dp_raw(args=args, data=data, dp_size=2)

        assert len(result) == 2
        assert "seq_witness_ids" in result[0]
        assert "seq_witness_ids" in result[1]
        assert len(result[0]["seq_witness_ids"]) == 2
        assert len(result[1]["seq_witness_ids"]) == 2

    def test_indexer_topk_and_opd_reverse_kl_split_across_dp(self) -> None:
        """Keys from the rollout-side split (rollout_indexer_topk, opd_reverse_kl) partition per sample."""
        data = {
            "tokens": [[1, 2], [3, 4], [5, 6], [7, 8]],
            "response_lengths": [1, 1, 1, 1],
            "loss_masks": [[0, 1], [0, 1], [0, 1], [0, 1]],
            "rollout_indexer_topk": [torch.tensor([i]) for i in range(4)],
            "opd_reverse_kl": [[float(i)] for i in range(4)],
        }

        args = MagicMock()
        args.balance_data = False

        result = split_train_data_by_dp_raw(args=args, data=data, dp_size=2)

        assert len(result) == 2
        for part in result:
            assert len(part["rollout_indexer_topk"]) == 2
            assert len(part["opd_reverse_kl"]) == 2

    def test_no_witness_ids_when_absent(self) -> None:
        tokens = [[1, 2], [3, 4]]
        data = {
            "tokens": tokens,
            "response_lengths": [1, 1],
            "loss_masks": [[0, 1], [0, 1]],
        }

        args = MagicMock()
        args.balance_data = False

        result = split_train_data_by_dp_raw(args=args, data=data, dp_size=1)
        assert "seq_witness_ids" not in result[0]


FULL_SCHEDULE_CONFIG = make_train_parallel_config(
    dp_size=2,
    cp_size=1,
    vpp_size=1,
    microbatch_group_size_per_vp_stage=None,
    independent_dp=False,
    supports_precomputed_schedule=True,
)


def _make_split_data(n: int, *, lengths: list[int] | None = None, rollout_ids: list[int] | None = None) -> dict:
    lengths = lengths or [2] * n
    assert len(lengths) == n
    return {
        "tokens": [list(range(length)) for length in lengths],
        "response_lengths": [1] * n,
        "rewards": [0.0] * n,
        "truncated": [0] * n,
        "loss_masks": [[1] * length for length in lengths],
        "sample_indices": list(range(n)),
        "lineage_source_sample_indices": list(range(n)),
        "lineage_output_indices": [0] * n,
        "lineage_output_counts": [1] * n,
        "rollout_ids": rollout_ids if rollout_ids is not None else list(range(n)),
    }


class TestCanPrecomputeDpSchedule:
    def test_eligible_with_full_megatron_config(self):
        args = make_args(balance_data=False, micro_batch_size=1, use_dynamic_batch_size=False, multi_lora=False)
        assert can_precompute_dp_schedule(
            args=args, data=_make_split_data(8), train_parallel_config=FULL_SCHEDULE_CONFIG
        )

    def test_rejects_partial_config(self):
        """Reject backends without precomputed schedule support or an advertised config."""
        args = make_args(balance_data=False, micro_batch_size=1, multi_lora=False)
        assert not can_precompute_dp_schedule(
            args=args,
            data=_make_split_data(8),
            train_parallel_config=make_train_parallel_config(dp_size=2, supports_precomputed_schedule=False),
        )
        assert not can_precompute_dp_schedule(args=args, data=_make_split_data(8), train_parallel_config=None)

    def test_rejects_multi_lora(self):
        args = make_args(balance_data=False, micro_batch_size=1, multi_lora=True)
        assert not can_precompute_dp_schedule(
            args=args, data=_make_split_data(8), train_parallel_config=FULL_SCHEDULE_CONFIG
        )

    @pytest.mark.parametrize(
        "multimodal_train_inputs",
        [
            {"pixel_values": torch.zeros(4, 3), "image_grid_thw": torch.tensor([[1, 2, 2]])},
            {"grid_thws": torch.tensor([[1, 4, 4]])},
            {"mm_vision_num_patches": torch.tensor([4])},
        ],
        ids=["qwen_vl", "kimi", "inkling"],
    )
    def test_accepts_image_batches(self, multimodal_train_inputs):
        args = make_args(balance_data=False, micro_batch_size=1, multi_lora=False)
        data = _make_split_data(8)
        data["multimodal_train_inputs"] = [multimodal_train_inputs] * 8
        assert can_precompute_dp_schedule(args=args, data=data, train_parallel_config=FULL_SCHEDULE_CONFIG)

    def test_rejects_fewer_rollouts_than_gbs(self):
        args = make_args(balance_data=False, micro_batch_size=1, multi_lora=False)  # global_batch_size=8
        assert not can_precompute_dp_schedule(
            args=args, data=_make_split_data(6), train_parallel_config=FULL_SCHEDULE_CONFIG
        )

    def test_accepts_trailing_partial_step(self):
        """Extra rollouts beyond a full step are fine — the schedule drops them."""
        args = make_args(balance_data=False, micro_batch_size=1, multi_lora=False)  # global_batch_size=8
        assert can_precompute_dp_schedule(
            args=args, data=_make_split_data(10), train_parallel_config=FULL_SCHEDULE_CONFIG
        )

    def test_dynamic_gbs_overrides_args_gbs(self):
        args = make_args(balance_data=False, micro_batch_size=1, multi_lora=False)  # global_batch_size=8
        data = _make_split_data(6)
        data["dynamic_global_batch_size"] = 6
        assert can_precompute_dp_schedule(args=args, data=data, train_parallel_config=FULL_SCHEDULE_CONFIG)


class TestSplitTrainDataByDpScheduled:
    def test_disabled_checker_schedules_without_witness_identity_columns(self) -> None:
        """Ordinary scheduling does not require model companion info metadata."""
        args = make_args(
            balance_data=False, micro_batch_size=2, use_dynamic_batch_size=False, enable_sample_ownership_checker=False
        )
        data = _make_split_data(8)
        del data["lineage_source_sample_indices"]
        del data["lineage_output_indices"]
        del data["lineage_output_counts"]

        shards = split_train_data_by_dp_scheduled_raw(args, data, train_parallel_config=FULL_SCHEDULE_CONFIG)

        assert sum(len(shard["tokens"]) for shard in shards) == 8

    def test_schedule_trim_resolves_only_the_rows_it_leaves_out(self, monkeypatch: pytest.MonkeyPatch) -> None:
        """Rows the DP schedule cannot place receive one terminal drop outcome."""
        args = make_args(
            balance_data=False, micro_batch_size=2, use_dynamic_batch_size=False, enable_sample_ownership_checker=True
        )
        calls: list[tuple[list[int], str]] = []
        monkeypatch.setattr(
            train_data_conversion.SampleOwnershipRecorder,
            "log_dropped_source_sample_indices",
            lambda *, args, source_sample_indices, reason: calls.append((list(source_sample_indices), reason)),
        )

        split_train_data_by_dp_scheduled_raw(args, _make_split_data(10), train_parallel_config=FULL_SCHEDULE_CONFIG)

        assert calls == [([8, 9], "dp_schedule_trim")]

    def test_static_shards_cover_all_samples(self):
        """Static path: every sample lands in exactly one shard row, the schedule
        tiles each shard's rows exactly, and shard rows match their partition."""
        args = make_args(balance_data=False, micro_batch_size=2, use_dynamic_batch_size=False)
        data = _make_split_data(8)
        scheduled = split_train_data_by_dp_scheduled_raw(
            args=args, data=dict(data), train_parallel_config=FULL_SCHEDULE_CONFIG
        )

        assert len(scheduled) == 2
        seen = []
        for new in scheduled:
            partition = list(new["partition"])
            seen.extend(partition)
            assert new["tokens"] == [data["tokens"][j] for j in partition]
            # global_batch_size=8, dp=2, mbs=2 -> 4 mbs total, 2 per rank, 1 step
            assert new["num_microbatches"] == [2]
            assert new["num_rollouts"] == [8]
            flat = [i for mbs in new["micro_batch_indices"] for i in mbs]
            assert flat == list(range(len(new["tokens"])))
        assert sorted(seen) == list(range(8))

    def test_compact_rollout_gbs_counts_rollouts_not_samples(self):
        """gbs counts rollouts: 4 rollouts over 6 samples with gbs=2 -> 2 steps,
        and every sample is still covered exactly once across shards."""
        args = make_args(balance_data=False, micro_batch_size=1, use_dynamic_batch_size=True, max_tokens_per_gpu=8)
        rollout_ids = [0, 1, 1, 1, 2, 3]  # rollout 1 emits 3 samples
        data = _make_split_data(6, rollout_ids=rollout_ids)
        data["dynamic_global_batch_size"] = 2
        shards = split_train_data_by_dp_scheduled_raw(
            args=args, data=dict(data), train_parallel_config=FULL_SCHEDULE_CONFIG
        )

        assert shards[0]["num_rollouts"] == [2, 2]
        assert len(shards[0]["num_microbatches"]) == 2
        seen = sorted(j for shard in shards for j in shard["partition"])
        assert seen == list(range(6))

    def test_dynamic_schedule_respects_token_cap(self):
        args = make_args(
            balance_data=False,
            micro_batch_size=1,
            use_dynamic_batch_size=True,
            max_tokens_per_gpu=6,
        )
        lengths = [5, 1, 4, 2, 3, 3, 2, 4]
        data = _make_split_data(8, lengths=lengths)
        shards = split_train_data_by_dp_scheduled_raw(args=args, data=data, train_parallel_config=FULL_SCHEDULE_CONFIG)

        nmb = shards[0]["num_microbatches"]
        for shard in shards:
            assert shard["num_microbatches"] == nmb, "num_microbatches must be identical on every rank"
            assert len(shard["micro_batch_indices"]) == sum(nmb)
            partition = list(shard["partition"])
            for mbs in shard["micro_batch_indices"]:
                total = sum(lengths[partition[i]] for i in mbs)
                assert total <= 6 or len(mbs) == 1

    def test_image_rollouts_of_several_samples_stay_whole_per_step(self):
        args = make_args(
            balance_data=False,
            micro_batch_size=1,
            use_dynamic_batch_size=True,
            max_tokens_per_gpu=8,
            global_batch_size=2,
        )
        rollout_ids = [0, 0, 0, 1, 1, 1, 2, 2, 3, 3]
        data = _make_split_data(10, rollout_ids=rollout_ids)
        data["multimodal_train_inputs"] = [{"pixel_values": torch.full((1, 3), float(i))} for i in range(10)]

        shards = split_train_data_by_dp_scheduled_raw(args, data, train_parallel_config=FULL_SCHEDULE_CONFIG)

        steps = _rollouts_per_step(shards, rollout_ids)
        assert [len(step) for step in steps] == [2, 2]
        assert sorted(rollout for step in steps for rollout in step) == [0, 1, 2, 3]
        assert all(shard["num_rollouts"] == [2, 2] for shard in shards)
        assert sorted(j for shard in shards for j in shard["partition"]) == list(range(10))
        for shard in shards:
            assert all(
                mm is data["multimodal_train_inputs"][j]
                for mm, j in zip(shard["multimodal_train_inputs"], shard["partition"], strict=True)
            )

    @pytest.mark.parametrize(
        ("media_token", "multimodal_train_inputs"),
        [
            (KIMI_VL_MEDIA_TOKEN_ID, {"grid_thws": torch.tensor([[1, 8, 8]])}),
            (INKLING_IMAGE_SENTINEL_ID, {"mm_vision_num_patches": torch.tensor([16])}),
        ],
        ids=["kimi", "inkling"],
    )
    def test_media_expanded_in_training_is_planned_at_its_trained_length(self, media_token, multimodal_train_inputs):
        args = make_args(
            balance_data=False,
            micro_batch_size=1,
            use_dynamic_batch_size=True,
            max_tokens_per_gpu=40,
            global_batch_size=4,
        )
        data = _make_split_data(4, lengths=[10] * 4)
        for tokens in data["tokens"]:
            tokens[0] = media_token
        data["multimodal_train_inputs"] = [dict(multimodal_train_inputs) for _ in range(4)]

        shards = split_train_data_by_dp_scheduled_raw(args, data, train_parallel_config=FULL_SCHEDULE_CONFIG)

        for shard in shards:
            assert shard["total_lengths"] == [10] * 4
            assert all(len(micro_batch) * 25 <= 40 for micro_batch in shard["micro_batch_indices"])

    def test_dynamic_gbs_multi_step(self):
        """16 samples with dynamic_global_batch_size=8 -> 2 steps."""
        args = make_args(balance_data=False, micro_batch_size=2, use_dynamic_batch_size=False)
        data = _make_split_data(16)
        data["dynamic_global_batch_size"] = 8
        shards = split_train_data_by_dp_scheduled_raw(args=args, data=data, train_parallel_config=FULL_SCHEDULE_CONFIG)

        assert shards[0]["num_microbatches"] == [2, 2]
        assert shards[0]["dynamic_global_batch_size"] == 8
        assert shards[0]["num_rollouts"] == [8, 8]


def _tagged_image_rollouts(samples_per_rollout: list[int]) -> dict:
    data = _make_split_data(
        sum(samples_per_rollout), rollout_ids=[r for r, n in enumerate(samples_per_rollout) for _ in range(n)]
    )
    data["tokens"] = [[i, i + 1000] for i in range(len(data["tokens"]))]
    data["multimodal_train_inputs"] = [
        {"image_grid_thw": torch.tensor([[1, 2, 2]]), "tag": torch.tensor([[i]])} for i in range(len(data["tokens"]))
    ]
    return data


def test_each_scheduled_micro_batch_carries_its_own_samples_images():
    args = make_args(balance_data=False, micro_batch_size=1, use_dynamic_batch_size=False, global_batch_size=2)
    shards = split_train_data_by_dp_scheduled_raw(
        args, _tagged_image_rollouts([3, 3, 2, 2]), train_parallel_config=FULL_SCHEDULE_CONFIG
    )

    for shard in shards:
        iterator = DataIterator(shard, micro_batch_indices=shard["micro_batch_indices"])
        for _ in shard["micro_batch_indices"]:
            batch = iterator.get_next(["tokens", "multimodal_train_inputs"])
            assert [mm["tag"].item() for mm in batch["multimodal_train_inputs"]] == [t[0] for t in batch["tokens"]]


def test_get_batch_concatenates_images_in_micro_batch_order(monkeypatch):
    state = SimpleNamespace(cp=SimpleNamespace(rank=0, size=1), tp=SimpleNamespace(rank=0, size=1))
    monkeypatch.setattr(data_rollout, "get_parallel_state", lambda: state)
    monkeypatch.setattr(context_parallel, "get_parallel_state", lambda: state)
    monkeypatch.setattr(data_rollout.current_platform, "current_device", lambda: torch.device("cpu"))
    lengths = [3, 2, 4]
    rollout = {
        "tokens": [torch.full((n,), i) for i, n in enumerate(lengths)],
        "loss_masks": [torch.ones(1, dtype=torch.int) for _ in lengths],
        "total_lengths": lengths,
        "response_lengths": [1] * 3,
        "multimodal_train_inputs": [
            {"image_grid_thw": torch.tensor([[1, 2, 2]]), "tag": torch.tensor([[i], [i]])} for i in range(3)
        ],
    }
    iterator = DataIterator(rollout, micro_batch_indices=[[2, 0], [1]])
    keys = ["tokens", "loss_masks", "total_lengths", "response_lengths", "multimodal_train_inputs"]

    first = data_rollout.get_batch(iterator, keys)
    second = data_rollout.get_batch(iterator, keys)

    assert first["multimodal_train_inputs"]["tag"].flatten().tolist() == [2, 2, 0, 0]
    assert first["multimodal_num_items"]["tag"] == [2, 2]
    assert [t[0].item() for t in first["unconcat_tokens"]] == [2, 0]
    assert second["multimodal_train_inputs"]["tag"].flatten().tolist() == [1, 1]


def _rollouts_per_step(shards: list[dict], rollout_ids: list[int]) -> list[set[int]]:
    steps = [set() for _ in shards[0]["num_microbatches"]]
    for shard in shards:
        micro_batches = iter(shard["micro_batch_indices"])
        for step, count in zip(steps, shard["num_microbatches"], strict=True):
            for _ in range(count):
                step.update(rollout_ids[shard["partition"][i]] for i in next(micro_batches))
    return steps


class TestSplitTrainDataRawRolloutCount:
    def test_stamps_the_rollout_count_of_a_single_step(self):
        args = make_args(balance_data=False, multi_lora=False, global_batch_size=5)
        data = _make_split_data(5, rollout_ids=[7, 7, 7, 9, 9])

        shards = split_train_data_by_dp_raw(args, data, dp_size=2)

        assert [shard["num_rollouts"] for shard in shards] == [[2], [2]]

    def test_refuses_several_steps_of_multi_sample_rollouts(self):
        args = make_args(balance_data=False, multi_lora=False, global_batch_size=2)
        data = _make_split_data(5, rollout_ids=[7, 7, 7, 9, 9])

        with pytest.raises(ValueError, match="can_precompute_dp_schedule") as error:
            split_train_data_by_dp_raw(args, data, dp_size=2)
        assert "--use-dynamic-global-batch-size" not in str(error.value)

    def test_single_sample_rollouts_and_multi_lora_keep_the_sample_count(self):
        args = make_args(balance_data=False, multi_lora=False, global_batch_size=2)
        assert "num_rollouts" not in split_train_data_by_dp_raw(args, _make_split_data(4), dp_size=2)[0]

        args = make_args(balance_data=False, multi_lora=True, global_batch_size=2)
        data = _make_split_data(5, rollout_ids=[7, 7, 7, 9, 9])
        assert "num_rollouts" not in split_train_data_by_dp_raw(args, data, dp_size=2)[0]


def test_delayed_dp_split_preserves_the_tinker_loss_vectors():
    """The tinker losses zip loss_weights / advantages / rollout_log_probs per
    datum; a key missing from the shard whitelist disappears silently and only
    fails inside the trainer."""
    from miles.ray.rollout.train_data_conversion import _package_shards

    data = {
        "tokens": [[1], [2], [3], [4]],
        "loss_weights": [[1.0]] * 4,
        "advantages": [[0.5]] * 4,
        "rollout_log_probs": [[-0.1]] * 4,
    }
    shards = _package_shards(None, data, [[0, 2], [1, 3]])
    for shard in shards:
        assert shard["loss_weights"] and shard["advantages"] and shard["rollout_log_probs"]
    assert shards[0]["advantages"] == [[0.5], [0.5]]


@pytest.mark.parametrize("scheduled", [False, True])
def test_dp_splits_carry_the_store_plans_per_row(scheduled: bool):
    """A key missing from the shard whitelist disappears silently; the trainer needs each row's plan."""
    data = _make_split_data(8)
    data["rollout_store_plan"] = [{"fields": {}, "refs": [{"key": f"k{i}"}]} for i in range(8)]
    args = make_args(balance_data=False, micro_batch_size=2, use_dynamic_batch_size=False)

    if scheduled:
        shards = split_train_data_by_dp_scheduled_raw(args, data, train_parallel_config=FULL_SCHEDULE_CONFIG)
    else:
        shards = split_train_data_by_dp_raw(args, data, dp_size=2)

    assert len(shards) == 2
    for shard in shards:
        assert shard["rollout_store_plan"] == [data["rollout_store_plan"][j] for j in shard["partition"]]


class TestOutputStoreTookEffect:
    def _convert(self, samples, **args):
        return convert_samples_to_train_data(
            make_args(rewards_normalization=False, **args),
            samples,
            metadata={},
            custom_convert_samples_to_train_data_func=None,
            custom_reward_post_process_func=None,
        )

    def test_inline_replay_under_the_switch_means_the_requests_never_opted_in(self):
        sample = make_sample()
        sample.rollout_sampling_mask = RolloutSamplingMask(ids=[1], offsets=[0, 1])

        with pytest.raises(StorePlanError, match="builds its own SGLang requests"):
            self._convert([sample], use_output_store=True)

    def test_without_replay_there_is_nothing_to_store(self):
        assert "rollout_store_plan" not in self._convert([make_sample()], use_output_store=True)


def _pad_data(rollout_ids, lengths=None):
    n = len(rollout_ids)
    return {
        "tokens": [[1] * length for length in lengths or [5000] * n],
        "response_lengths": [10] * n,
        "rewards": [1.0] * n,
        "raw_reward": [float(i) for i in range(n)],
        "truncated": [0] * n,
        "sample_indices": [100 + i for i in range(n)],
        "rollout_ids": list(rollout_ids),
        "loss_masks": [[1] * 10 for _ in range(n)],
        "rollout_mask_sums": [10] * n,
        "rollout_log_probs": [[-0.1] * 10 for _ in range(n)],
        "weight_versions": [[{"spans": []}]] * n,
        "prompt_group_sizes": [1] * n,
    }


def _split_padded(data, *, dp_size=2, pad=True, **overrides):
    args = make_args(
        use_dynamic_batch_size=True,
        max_tokens_per_gpu=8192,
        pad_steps_for_dp_alignment=pad,
        **{"global_batch_size": len(set(data["rollout_ids"])), **overrides},
    )
    config = make_train_parallel_config(dp_size=dp_size, supports_precomputed_schedule=True)
    return split_train_data_by_dp(args, data, config)


def _rows(shards):
    return [
        {key: shard[key][k] for key in ("tokens", "loss_masks", "response_lengths", "rollout_ids", "sample_indices")}
        | {"partition": j}
        for shard in shards
        for k, j in enumerate(shard["partition"])
    ]


class TestPadStepsForDpAlignment:
    def test_without_the_flag_the_step_is_refused(self):
        with pytest.raises(AssertionError, match="could only produce 3 micro-batches"):
            _split_padded(_pad_data([7, 8, 9]), pad=False)

    def test_a_pad_row_is_zero_loss_and_keeps_its_templates_rollout(self):
        shards = _split_padded(_pad_data([7, 8, 9]))
        [(shard, k)] = [(shard, k) for shard in shards for k, j in enumerate(shard["partition"]) if j == 3]
        pad = {key: shard[key][k] for key in ("tokens", "loss_masks", "response_lengths", "rewards")}
        pad |= {key: shard[key][k] for key in ("rollout_log_probs", "weight_versions", "rollout_ids")}
        pad |= {key: shard[key][k] for key in ("rollout_mask_sums", "sample_indices")}
        assert pad["tokens"] == [0, 0]
        assert pad["loss_masks"] == [0]
        assert pad["response_lengths"] == 1
        assert pad["rewards"] == 0.0
        assert pad["rollout_log_probs"] == [0.0]
        assert pad["weight_versions"] == []
        assert (pad["rollout_ids"], pad["rollout_mask_sums"], pad["sample_indices"]) == (7, 10, 100)
        assert all(shard["total_lengths"][3] == 2 for shard in shards)

    def test_batch_global_columns_keep_one_entry_per_real_sample(self):
        data = _pad_data([7, 8, 9])
        shards = _split_padded(data)
        for shard in shards:
            assert shard["raw_reward"] == [0.0, 1.0, 2.0]
            assert shard["prompt_group_sizes"] == [1, 1, 1]
        real = [row for row in _rows(shards) if row["partition"] < 3]
        assert sorted(row["partition"] for row in real) == [0, 1, 2]
        for row in real:
            assert row["sample_indices"] == data["sample_indices"][row["partition"]]
            assert row["tokens"] == data["tokens"][row["partition"]]

    def test_replay_columns_are_cut_to_the_pad_row(self):
        data = _pad_data([7, 8, 9])
        data["rollout_topk_token_ids"] = [np.arange(40).reshape(10, 4)] * 3
        data["rollout_topk_log_probs"] = [np.zeros((10, 4))] * 3
        data["rollout_sampling_mask_offsets"] = [np.arange(0, 33, 3)] * 3
        data["rollout_sampling_mask_ids"] = [np.arange(30)] * 3
        data["rollout_routed_experts"] = [np.ones((4999, 2, 3), dtype=np.int32)] * 3
        shards = _split_padded(data)
        [(shard, k)] = [(shard, k) for shard in shards for k, j in enumerate(shard["partition"]) if j == 3]
        assert shard["rollout_topk_token_ids"][k].tolist() == [[0, 1, 2, 3]]
        assert shard["rollout_topk_log_probs"][k].shape == (1, 4)
        assert shard["rollout_sampling_mask_offsets"][k].tolist() == [0, 3]
        assert shard["rollout_sampling_mask_ids"][k].tolist() == [0, 1, 2]
        assert shard["rollout_routed_experts"][k].shape == (1, 2, 3)

    @pytest.mark.parametrize("length", [8192, 8191, 9000])
    def test_an_already_aligned_step_gets_no_pad(self, length):
        shards = _split_padded(_pad_data([0, 1], lengths=[length, length]))
        assert sorted(row["partition"] for row in _rows(shards)) == [0, 1]

    def test_an_eligible_partial_step_is_padded_too(self):
        shards = _split_padded(_pad_data([0, 1, 2, 2, 2]), global_batch_size=2, allow_partial_train_step=True)
        assert shards[0]["num_rollouts"] == [2, 1]
        rows = _rows(shards)
        assert sorted(row["partition"] for row in rows) == [0, 1, 2, 3, 4, 5]
        assert [row["rollout_ids"] for row in rows if row["partition"] == 5] == [2]

    def test_dp_one_needs_no_padding(self):
        shards = _split_padded(_pad_data([0, 1, 2]), dp_size=1)
        assert len(shards[0]["tokens"]) == 3


def _over_half_cap_round(pad):
    """A Harbor 2x1080p round needed 196 micro-batches at DP 2 but could produce 195."""
    rng = random.Random(0)
    data = _pad_data(list(range(195)), lengths=[rng.randint(4100, 8192) for _ in range(195)])
    return data, lambda: _split_padded(data, pad=pad)


def test_a_round_of_samples_over_half_the_cap_cannot_be_scheduled_without_padding():
    _, split = _over_half_cap_round(pad=False)
    with pytest.raises(AssertionError, match="could only produce 195 micro-batches after maximal splitting; need 196"):
        split()


def test_a_round_of_samples_over_half_the_cap_trains_every_sample_with_padding():
    data, split = _over_half_cap_round(pad=True)
    rows = _rows(split())
    assert len(rows) == 196
    assert sorted(row["partition"] for row in rows if row["partition"] < 195) == list(range(195))
    [pad] = [row for row in rows if row["partition"] == 195]
    assert (pad["tokens"], pad["loss_masks"], pad["rollout_ids"]) == ([0, 0], [0], 0)
