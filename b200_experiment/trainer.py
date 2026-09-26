from __future__ import annotations

import copy
import csv
import hashlib
import json
import math
import os
import random
import shutil
import subprocess
import sys
import tempfile
import time
import warnings
from contextlib import nullcontext
from collections.abc import Callable
from pathlib import Path
from typing import Any

import numpy as np
import torch
from torch.nn.parallel import DistributedDataParallel
from tqdm.auto import tqdm

from .config import save_config
from .data import (
    epoch_batch_indices,
    expand_prompt_batch,
    filter_overlong_prompt_records,
    read_records,
    render_record_prompt,
    stable_sample_id,
    tokenize_prompts,
    validate_prompt_records,
)
from .diagnostics import correlations, finite_or_raise, selector_summary
from .distributed import (
    BatchLayout,
    DistributedContext,
    batch_layout,
    contiguous_partition,
    distributed_ppo_minibatch_partition,
    grouped_ppo_minibatch_partition,
    initialize_distributed,
    isolate_distributed_subprocess_environment,
    padded_local_indices,
    unique_free_port,
    unwrap_model,
)
from .evaluation import (
    configured_benchmark_names,
    evaluate_loaded_suite,
    evaluation_metric_name,
    grade_evaluation_response,
    load_benchmark,
    render_evaluation_prompt,
)
from .evaluation_cache import (
    base_evaluation_cache_key,
    evaluate_or_reuse_base,
    load_compatible_evaluation,
    materialize_evaluation,
    resolve_base_cache_root,
)
from .eval_schedule import (
    should_run_training_evaluation,
    training_evaluation_steps,
)
from .metadata import collect_metadata, save_metadata
from .models import (
    is_qwen35_composite_text_model,
    load_models,
    load_student_model,
    load_student_tokenizer,
    qwen35_composite_weight_name,
    validate_shared_tokenizer_protocol,
)
from .fsdp import (
    clip_grad_norm,
    distributed_strategy,
    full_model_state_dict,
    full_optimizer_state_dict,
    is_fsdp_model,
    wrap_fsdp_model,
)
from .opd_core import (
    UPSTREAM_ADV_ESTIMATOR,
    UPSTREAM_LOSS_AGG_MODE,
    DEFAULT_OPD_TOP_K,
    UPSTREAM_OPD_COMMIT,
    UPSTREAM_REWARD_WEIGHT_MODE,
    UPSTREAM_TOP_K_STRATEGY,
    TopKOPDReference,
    build_iw_opd_reference,
    build_student_topk_opd_reference,
    build_topk_opd_reference,
    gather_candidate_log_probs,
    topk_candidate_ppo_loss,
    topk_overlap_fraction,
    weighted_token_sums,
)
from .resume import (
    resolve_resume_checkpoint,
    restore_optimizer,
    validate_append_history,
    validate_resume_config,
)
from .scoring import (
    cuda_sync,
    generate_on_policy,
    position_ids_from_mask,
    score_original_rollout,
    score_student_teacher_rollout,
    supports_response_only_logits,
)
from .selector_logging import (
    CMTTokenAuditLogger,
    SelectedTokenLogger,
    TokenScoreStatsLogger,
    cmt_motivation_summary,
)
from .selectors import (
    CMTSelector,
    OPDSelector,
    PGTSelector,
    RACSelector,
    TASelector,
    cmt_allocation,
    cmt_weight_metrics,
    robust_cmt_correction,
    top_budget_mask,
    validate_cmt_allocation,
    validate_cmt_correction,
)
from .selectors.pgt_selector import PGTOutput
from .selectors.base import SelectorOutput, robust_quantile_normalize, scatter_valid
from .tensorboard_logging import TensorBoardLogger
from .vllm_evaluation import (
    _terminate_process_group,
    merge_vllm_evaluation_shards,
)
from .vllm_rollout import VLLMRolloutEngine


METHOD_DISPLAY_NAMES = {
    "opd": "OPD",
    "ta": "TA-OPD",
    "rac": "Bellman-RAC",
    "pgt": "PGT",
    "cmt": "CMT-OPD",
    "grpo": "GRPO",
    "iw": "IW-OPD",
}


def seed_everything(seed: int) -> None:
    random.seed(seed)
    np.random.seed(seed)
    torch.manual_seed(seed)
    torch.cuda.manual_seed_all(seed)


def _micro_batch_size_per_gpu(
    training: dict[str, Any],
    world_size: int,
    global_ppo_batch_size: int | None = None,
) -> int:
    if "micro_batch_size_per_gpu" in training:
        value = int(training["micro_batch_size_per_gpu"])
    elif "micro_batch_size" in training:
        if world_size > 1:
            raise ValueError(
                "training.micro_batch_size is a legacy ambiguous global value. "
                "Set training.micro_batch_size_per_gpu explicitly for distributed "
                "training."
            )
        value = int(training["micro_batch_size"])
    else:
        raise ValueError("training.micro_batch_size_per_gpu is required")
    if value <= 0:
        raise ValueError("training.micro_batch_size_per_gpu must be positive")
    if global_ppo_batch_size is not None:
        if global_ppo_batch_size <= 0:
            raise ValueError("global PPO mini-batch size must be positive")
        # PPO_MINI_BATCH_SIZE is global.  A microbatch is local and should not
        # exceed the largest rank share of one global PPO minibatch.
        value = min(value, (int(global_ppo_batch_size) + world_size - 1) // world_size)
    return value


def _ppo_mini_batch_size(
    training: dict[str, Any], global_trajectory_batch_size: int
) -> int:
    value = int(training.get("ppo_mini_batch_size", global_trajectory_batch_size))
    if value <= 0:
        raise ValueError("training.ppo_mini_batch_size must be positive")
    return value


def _ppo_minibatch_count(global_trajectory_count: int, ppo_size: int) -> int:
    if global_trajectory_count <= 0 or ppo_size <= 0:
        raise ValueError("Trajectory count and PPO mini-batch size must be positive")
    return (global_trajectory_count + ppo_size - 1) // ppo_size


def _optimizer_steps_per_epoch(
    num_records: int,
    prompt_batch_size: int,
    num_responses: int,
    ppo_size: int,
) -> int:
    total = 0
    for begin in range(0, num_records, prompt_batch_size):
        prompt_count = min(prompt_batch_size, num_records - begin)
        total += _ppo_minibatch_count(prompt_count * num_responses, ppo_size)
    return total


def _rollout_position_after_optimizer_steps(
    completed_steps: int,
    num_records: int,
    prompt_batch_size: int,
    num_responses: int,
    ppo_size: int,
) -> tuple[int, int]:
    """Map optimizer-step state to deterministic rollout/minibatch position."""
    if completed_steps < 0:
        raise ValueError("completed_steps cannot be negative")
    rollout_batches = math.ceil(num_records / prompt_batch_size)
    steps_per_epoch = _optimizer_steps_per_epoch(
        num_records, prompt_batch_size, num_responses, ppo_size
    )
    epoch, remaining = divmod(completed_steps, steps_per_epoch)
    for slot in range(rollout_batches):
        prompt_count = min(prompt_batch_size, num_records - slot * prompt_batch_size)
        count = _ppo_minibatch_count(prompt_count * num_responses, ppo_size)
        if remaining < count:
            return epoch * rollout_batches + slot, remaining
        remaining -= count
    return (epoch + 1) * rollout_batches, 0


def _format_batch_layout(
    layout: BatchLayout,
    strategy: str,
    config: dict[str, Any],
) -> str:
    fsdp = config.get("distributed", {}).get("fsdp", {})
    training = config["training"]
    method = str(config.get("experiment", {}).get("method", "")).lower()
    lines = [
        f"distributed strategy          = {strategy}",
        f"world_size                    = {layout.world_size}",
        f"global_prompt_batch_size      = {layout.global_prompt_batch_size}",
        f"local_prompt_batch_size       = {layout.local_prompt_batch_size}",
        f"num_responses                 = {layout.num_responses}",
        f"global_trajectory_batch_size  = {layout.global_trajectory_batch_size}",
        f"local_trajectory_batch_size   = {layout.local_trajectory_batch_size}",
        f"ppo_mini_batch_size           = {layout.ppo_mini_batch_size}",
        f"local_ppo_mini_batch_size      = {layout.local_ppo_mini_batch_size}",
        f"optimizer_steps/full_rollout  = {layout.optimizer_steps_per_full_rollout}",
        f"trajectories/full_rollout     = {layout.global_trajectory_batch_size}",
        f"PPO groups/full_rollout       = {layout.optimizer_steps_per_full_rollout}",
        f"micro_batch_size_per_gpu      = {layout.micro_batch_size_per_gpu}",
        f"micro_batches_per_gpu         = {layout.micro_batches_per_gpu}",
        f"learning_rate                 = {float(training['learning_rate']):.8g}",
        f"max_prompt_tokens             = {int(config['data']['max_prompt_tokens'])}",
        f"max_response_tokens           = {int(config['rollout']['max_new_tokens'])}",
        "student_sharding_strategy     = "
        + ("FULL_SHARD" if strategy == "fsdp" else "none"),
        "teacher_sharding              = "
        + ("FULL_SHARD" if strategy == "fsdp" else "replicated"),
        "teacher_cpu_offload           = "
        + str(bool(fsdp.get("teacher_cpu_offload", False))).lower(),
        "gradient_checkpointing        = "
        + str(bool(training.get("gradient_checkpointing", False))).lower(),
    ]
    if method == "cmt":
        lines.extend(
            (
                "Gibbs allocations/full_rollout = "
                f"{layout.optimizer_steps_per_full_rollout}",
                f"trajectories/Gibbs          = {layout.ppo_mini_batch_size}",
            )
        )
    return "\n".join(lines)


def _timed(device: torch.device, function, *args, **kwargs):
    cuda_sync(device)
    started = time.perf_counter()
    result = function(*args, **kwargs)
    cuda_sync(device)
    return result, time.perf_counter() - started


def _globalize_ta_output(
    local: SelectorOutput,
    valid_mask: torch.Tensor,
    selector: TASelector,
    distributed: DistributedContext,
) -> tuple[SelectorOutput, dict[str, torch.Tensor], int, int]:
    """Apply TA's quantile normalization over the true global rollout batch."""
    global_d, start, end, lengths = distributed.all_gather_variable_1d(
        local.diagnostics["D"][valid_mask]
    )
    global_c, c_start, c_end, c_lengths = distributed.all_gather_variable_1d(
        local.diagnostics["C"][valid_mask]
    )
    if (start, end, lengths) != (c_start, c_end, c_lengths):
        raise AssertionError("Distributed TA D/C layouts differ")
    global_d_norm = robust_quantile_normalize(
        global_d, selector.q_low, selector.q_high, selector.eps
    )
    global_c_norm = robust_quantile_normalize(
        global_c, selector.q_low, selector.q_high, selector.eps
    )
    global_score = global_d_norm * global_c_norm
    diagnostics = dict(local.diagnostics)
    diagnostics.update(
        D_norm=scatter_valid(global_d_norm[start:end], valid_mask),
        C_norm=scatter_valid(global_c_norm[start:end], valid_mask),
        s_TA=scatter_valid(global_score[start:end], valid_mask),
    )
    global_diagnostics = {
        "D": global_d,
        "C": global_c,
        "D_norm": global_d_norm,
        "C_norm": global_c_norm,
        "s_TA": global_score,
    }
    return (
        SelectorOutput(diagnostics["s_TA"], diagnostics),
        global_diagnostics,
        start,
        end,
    )


def _gather_selector_diagnostics(
    diagnostics: dict[str, Any],
    valid_mask: torch.Tensor,
    keys: tuple[str, ...],
    distributed: DistributedContext,
) -> tuple[dict[str, torch.Tensor], int, int]:
    gathered: dict[str, torch.Tensor] = {}
    layout: tuple[int, int, tuple[int, ...]] | None = None
    for key in keys:
        value = diagnostics.get(key)
        if not torch.is_tensor(value) or value.shape != valid_mask.shape:
            continue
        combined, start, end, lengths = distributed.all_gather_variable_1d(
            value[valid_mask]
        )
        current_layout = (start, end, lengths)
        if layout is None:
            layout = current_layout
        elif layout != current_layout:
            raise AssertionError(f"Distributed selector layout differs for {key}")
        gathered[key] = combined
    if layout is None:
        raise ValueError("No token-shaped selector diagnostics were available")
    return gathered, layout[0], layout[1]


def _globalize_opd_output(
    local: SelectorOutput,
    valid_mask: torch.Tensor,
    distributed: DistributedContext,
) -> tuple[SelectorOutput, dict[str, torch.Tensor], int, int]:
    """Gather uniform pure-OPD weights for global metrics and auditing."""
    gathered, start, end = _gather_selector_diagnostics(
        local.diagnostics, valid_mask, ("w",), distributed
    )
    return local, gathered, start, end


def _globalize_pgt_output(
    local: PGTOutput,
    valid_mask: torch.Tensor,
    distributed: DistributedContext,
) -> tuple[PGTOutput, dict[str, torch.Tensor], int, int]:
    """Gather PGT's local natural-gradient gains for a global token budget."""
    keys = (
        "gain",
        "s_PGT",
        "euclidean_gain",
        "restricted_reverse_kl",
        "student_support_mass",
        "teacher_support_mass",
        "teacher_tail_mass",
        "support_width",
    )
    gathered, start, end = _gather_selector_diagnostics(
        local.diagnostics, valid_mask, keys, distributed
    )
    return local, gathered, start, end


def _globalize_cmt_output(
    local: PGTOutput,
    valid_mask: torch.Tensor,
    distributed: DistributedContext,
) -> tuple[SelectorOutput, dict[str, torch.Tensor], int, int]:
    """Gather CMT scores; Gibbs allocation is intentionally PPO-group local."""
    keys = (
        "gain",
        "s_PGT",
        "support_reverse_kl",
        "support_common_mass",
        "conditional_support_common_mass",
        "sampled_log_ratio",
        "sampled_conditional_log_ratio",
        "alignment",
        "transition_weight",
        "support_coverage",
        "coverage_correction",
        "teacher_deficit",
        "signed_reachability_shift",
        "compatibility_weight",
        "marginal_flux",
        "downstream_effect",
        "common_mass_derivative",
        "R",
        "M",
        "V",
        "H",
        "successor_excess",
        "successor_return",
        "successor_mass",
        "successor_value",
        "successor_excess_total",
        "successor_excess_average",
        "successor_R",
        "sequential_gain",
        "sequential_gain_raw",
        "learning_value",
        "learning_value_raw",
        "s_CMT",
        "student_support_mass",
        "teacher_support_mass",
        "teacher_tail_mass",
        "support_width",
    )
    optional_full_keys = (
        "full_log_ratio_mean",
        "full_log_ratio_variance",
        "full_common_mass",
    )
    keys = keys + tuple(key for key in optional_full_keys if key in local.diagnostics)
    gathered, start, end = _gather_selector_diagnostics(
        local.diagnostics, valid_mask, keys, distributed
    )
    # Do not solve one allocation here: this tensor spans the complete rollout
    # (e.g. 64 prompts x 4 responses = 256 trajectories), whereas each optimizer
    # update consumes one global PPO group (e.g. 64 trajectories). The solver is
    # called inside _opd_train_step on exactly the rows used by that update.
    return (
        SelectorOutput(local.diagnostics["s_CMT"], dict(local.diagnostics)),
        gathered,
        start,
        end,
    )


@torch.no_grad()
def _apply_global_cmt_correction(
    local: SelectorOutput,
    global_diagnostics: dict[str, torch.Tensor],
    valid_mask: torch.Tensor,
    start: int,
    end: int,
    *,
    mode: str,
    quantile: float,
) -> tuple[SelectorOutput, dict[str, torch.Tensor], dict[str, float]]:
    """Correct raw CMT D once on the rollout-global valid-token population."""
    robust_d, robust_value, kappa, metrics = robust_cmt_correction(
        global_diagnostics["gain"],
        global_diagnostics["sequential_gain_raw"],
        mode=mode,
        quantile=quantile,
    )
    ablation_arm = str(local.diagnostics.get("ablation_arm", "canonical"))
    d_only = ablation_arm == "d_only"
    raw_value = (
        global_diagnostics["sequential_gain_raw"]
        if d_only
        else global_diagnostics["gain"]
        + global_diagnostics["sequential_gain_raw"]
    )
    corrected_value = robust_d if d_only else robust_value
    kappa_values = torch.full_like(corrected_value, float(kappa))
    if mode == "none":
        # Preserve every legacy/ablation score exactly in the default mode.
        global_allocation_score = global_diagnostics["s_CMT"]
        local_allocation_score = local.scores
    else:
        global_allocation_score = corrected_value
        local_allocation_score = scatter_valid(
            corrected_value[start:end], valid_mask
        )
    diagnostics = dict(local.diagnostics)
    diagnostics.update(
        sequential_gain_raw=scatter_valid(
            global_diagnostics["sequential_gain_raw"][start:end], valid_mask
        ),
        learning_value_raw=scatter_valid(raw_value[start:end], valid_mask),
        correction_kappa=scatter_valid(kappa_values[start:end], valid_mask),
        sequential_gain_robust=scatter_valid(robust_d[start:end], valid_mask),
        learning_value_robust=scatter_valid(
            corrected_value[start:end], valid_mask
        ),
        allocation_score=local_allocation_score,
        correction_mode=mode,
        correction_quantile=float(quantile),
    )
    # s_CMT is the score actually supplied to allocation. Raw aliases remain
    # explicitly available as sequential_gain_raw/learning_value_raw.
    diagnostics["s_CMT"] = local_allocation_score
    global_diagnostics.update(
        sequential_gain_raw=global_diagnostics["sequential_gain_raw"],
        learning_value_raw=raw_value,
        correction_kappa=kappa_values,
        sequential_gain_robust=robust_d,
        learning_value_robust=corrected_value,
        allocation_score=global_allocation_score,
        s_CMT=global_allocation_score,
    )
    return (
        SelectorOutput(local_allocation_score, diagnostics),
        global_diagnostics,
        metrics,
    )


def _globalize_rac_output(
    local: SelectorOutput,
    valid_mask: torch.Tensor,
    selector: RACSelector,
    distributed: DistributedContext,
) -> tuple[SelectorOutput, dict[str, torch.Tensor], int, int]:
    """Normalize Bellman V over the true global rollout and build soft weights."""
    keys = ("g", "alignment", "R", "M", "V")
    gathered, start, end = _gather_selector_diagnostics(
        local.diagnostics, valid_mask, keys, distributed
    )
    global_z = robust_quantile_normalize(
        gathered["V"], selector.q_low, selector.q_high, selector.eps
    )
    global_weights = selector.w_min + (1.0 - selector.w_min) * global_z.pow(
        selector.beta
    )
    diagnostics = dict(local.diagnostics)
    diagnostics.update(
        z=scatter_valid(global_z[start:end], valid_mask),
        w=scatter_valid(global_weights[start:end], valid_mask),
    )
    gathered.update(z=global_z, w=global_weights)
    return SelectorOutput(diagnostics["w"], diagnostics), gathered, start, end


def _local_mask_from_global_budget(
    global_scores: torch.Tensor,
    local_valid_mask: torch.Tensor,
    start: int,
    end: int,
    rho: float,
) -> tuple[torch.Tensor, torch.Tensor]:
    global_valid = torch.ones_like(global_scores, dtype=torch.bool)
    global_selected = top_budget_mask(global_scores, global_valid, rho)
    local_selected = torch.zeros_like(local_valid_mask, dtype=torch.bool)
    local_selected[local_valid_mask] = global_selected[start:end]
    return local_selected, global_selected


def _rollout_hash(
    response_ids: torch.Tensor,
    valid_mask: torch.Tensor,
    distributed: DistributedContext,
) -> str:
    serialized = []
    for row_ids, row_valid in zip(response_ids, valid_mask):
        tokens = row_ids[row_valid].long()
        if tokens.numel() == 0:
            continue
        serialized.append(
            torch.cat(
                (
                    torch.tensor([tokens.numel()], device=tokens.device),
                    tokens,
                )
            )
        )
    local = (
        torch.cat(serialized)
        if serialized
        else torch.empty(0, dtype=torch.long, device=distributed.device)
    )
    combined, _, _, _ = distributed.all_gather_variable_1d(local)
    return hashlib.sha256(combined.detach().cpu().numpy().tobytes()).hexdigest()


def _append_jsonl(path: Path, payload: dict[str, Any]) -> None:
    path.parent.mkdir(parents=True, exist_ok=True)
    with path.open("a", encoding="utf-8") as handle:
        handle.write(json.dumps(payload, ensure_ascii=False, allow_nan=True) + "\n")


def _append_csv_row(
    path: Path, row: dict[str, Any], fieldnames: tuple[str, ...]
) -> None:
    path.parent.mkdir(parents=True, exist_ok=True)
    exists = path.is_file() and path.stat().st_size > 0
    with path.open("a", newline="", encoding="utf-8") as handle:
        writer = csv.DictWriter(handle, fieldnames=fieldnames, extrasaction="ignore")
        if not exists:
            writer.writeheader()
        writer.writerow(row)


def _upsert_jsonl_row(
    path: Path, payload: dict[str, Any], key_fields: tuple[str, ...]
) -> None:
    """Atomically insert/replace a row so a pre-train retry cannot duplicate step 0."""
    rows: list[dict[str, Any]] = []
    if path.is_file():
        with path.open(encoding="utf-8") as handle:
            rows = [json.loads(line) for line in handle if line.strip()]

    def matches(row: dict[str, Any]) -> bool:
        return all(row.get(key) == payload.get(key) for key in key_fields)

    output: list[dict[str, Any]] = []
    replaced = False
    for row in rows:
        if matches(row):
            if not replaced:
                output.append(payload)
                replaced = True
        else:
            output.append(row)
    if not replaced:
        output.append(payload)
    path.parent.mkdir(parents=True, exist_ok=True)
    temporary = path.with_name(f".{path.name}.{os.getpid()}.tmp")
    with temporary.open("w", encoding="utf-8") as handle:
        for row in output:
            handle.write(json.dumps(row, ensure_ascii=False, allow_nan=True) + "\n")
    os.replace(temporary, path)


def _upsert_csv_row(
    path: Path,
    row: dict[str, Any],
    fieldnames: tuple[str, ...],
    key_fields: tuple[str, ...],
) -> None:
    rows: list[dict[str, Any]] = []
    if path.is_file() and path.stat().st_size > 0:
        with path.open(newline="", encoding="utf-8") as handle:
            rows = list(csv.DictReader(handle))

    def matches(item: dict[str, Any]) -> bool:
        return all(str(item.get(key)) == str(row.get(key)) for key in key_fields)

    output: list[dict[str, Any]] = []
    replaced = False
    for existing in rows:
        if matches(existing):
            if not replaced:
                output.append(row)
                replaced = True
        else:
            output.append(existing)
    if not replaced:
        output.append(row)
    path.parent.mkdir(parents=True, exist_ok=True)
    temporary = path.with_name(f".{path.name}.{os.getpid()}.tmp")
    with temporary.open("w", newline="", encoding="utf-8") as handle:
        writer = csv.DictWriter(handle, fieldnames=fieldnames, extrasaction="ignore")
        writer.writeheader()
        writer.writerows(output)
    os.replace(temporary, path)


def _append_train_metrics_csv(path: Path, metrics: dict[str, Any]) -> None:
    selector = metrics.get("selector", {})
    row = {
        key: value
        for key, value in metrics.items()
        if not isinstance(value, (dict, list, tuple))
    }
    for score in (
        "D",
        "C",
        "s_TA",
        "g",
        "alignment",
        "R",
        "M",
        "V",
        "z",
        "w",
        "gain",
        "s_PGT",
        "euclidean_gain",
        "restricted_reverse_kl",
        "student_support_mass",
        "teacher_support_mass",
        "teacher_tail_mass",
        "support_width",
        "support_common_mass",
        "conditional_support_common_mass",
        "transition_weight",
        "support_coverage",
        "coverage_correction",
        "teacher_deficit",
        "signed_reachability_shift",
        "compatibility_weight",
        "marginal_flux",
        "downstream_effect",
        "common_mass_derivative",
        "H",
        "successor_excess",
        "sequential_gain",
        "learning_value",
        "s_CMT",
        "iw_weight",
    ):
        for statistic, value in selector.get(score, {}).items():
            row[f"{score}_{statistic}"] = value
    for key in (
        "selected_tokens",
        "selected_fraction",
        "selection_threshold",
        "effective_token_weight_mass",
        "effective_sample_size",
        "marginal_flux_positive_fraction",
        "marginal_flux_negative_fraction",
    ):
        row[key] = selector.get(key)
    common = (
        "step",
        "epoch",
        "method",
        "lr",
        "train_loss",
        "weighted_final_loss",
        "base_topk_opd_loss",
        "unweighted_opd_loss",
        "student_entropy",
        "teacher_entropy",
        "entropy_gap",
        "topk_student_mass",
        "topk_teacher_mass",
        "topk_divergence_proxy_mean",
        "topk_divergence_proxy_min",
        "topk_divergence_proxy_max",
        "opd_ratio_mean",
        "opd_ratio_min",
        "opd_ratio_max",
        "opd_clip_fraction",
        "opd_advantage_mean",
        "opd_advantage_abs_mean",
        "opd_advantage_min",
        "opd_advantage_max",
        "iw_weight_mean",
        "iw_weight_std",
        "iw_weight_min",
        "iw_weight_max",
        "grad_norm",
        "num_valid_tokens",
        "mean_response_length",
        "min_response_length",
        "max_response_length",
        "response_clip_ratio",
        "student_teacher_topk_overlap_ratio",
        "student_teacher_topk_divergence_proxy",
        "throughput_tokens_per_sec",
        "rollout_time",
        "total_scoring_time_sec",
        "joint_student_teacher_scoring_time",
        "teacher_score_time_sec",
        "student_cross_topk_scoring_time",
        "ta_local_score_time_sec",
        "bellman_scan_time_sec",
        "forward_backward_time_sec",
        "optimizer_time_sec",
        "peak_gpu_allocated_gb",
        "peak_gpu_reserved_gb",
        "selected_tokens",
        "selected_fraction",
        "selection_threshold",
        "effective_token_weight_mass",
        "effective_sample_size",
        "marginal_flux_positive_fraction",
        "marginal_flux_negative_fraction",
        "ppo_minibatch_trajectory_count",
        "local_ppo_minibatch_trajectory_count",
        "rollout_id",
        "optimizer_step",
        "ppo_group_index",
        "group_valid_token_count",
        "correction_kappa",
        "sequential_gain_raw_abs_q95",
        "sequential_gain_raw_abs_q99",
        "sequential_gain_robust_abs_q95",
        "sequential_gain_robust_abs_q99",
        "correction_saturation_rate_1kappa",
        "correction_saturation_rate_2kappa",
        "allocation_beta",
        "allocation_log_c",
        "allocation_kl_target",
        "allocation_kl_final",
        "allocation_mean_weight_error",
        "fraction_at_weight_min",
        "fraction_at_weight_max",
        "normalized_ess",
        "max_token_probability",
        "allocation_solver_status",
    )
    statistics = tuple(
        f"{score}_{statistic}"
        for score in (
            "D",
            "C",
            "s_TA",
            "g",
            "alignment",
            "R",
            "M",
            "V",
            "z",
            "w",
            "gain",
            "s_PGT",
            "euclidean_gain",
            "restricted_reverse_kl",
            "student_support_mass",
            "teacher_support_mass",
            "teacher_tail_mass",
            "support_width",
            "support_common_mass",
            "conditional_support_common_mass",
            "transition_weight",
            "support_coverage",
            "coverage_correction",
            "teacher_deficit",
            "signed_reachability_shift",
            "compatibility_weight",
            "marginal_flux",
            "downstream_effect",
            "common_mass_derivative",
            "H",
            "successor_excess",
            "sequential_gain",
            "learning_value",
            "s_CMT",
            "iw_weight",
        )
        for statistic in (
            "mean",
            "std",
            "min",
            "max",
            "q05",
            "q25",
            "q50",
            "q75",
            "q95",
        )
    )
    _append_csv_row(path, row, common + statistics)


def _save_inference_snapshot(
    model,
    tokenizer,
    destination: Path,
    distributed: DistributedContext | None = None,
) -> None:
    """Export a normal HF checkpoint; every FSDP rank enters collectives."""
    if is_fsdp_model(model) and distributed is None:
        raise RuntimeError("FSDP snapshot export requires distributed context")
    raw_model = unwrap_model(model)
    previous_use_cache = raw_model.config.use_cache
    raw_model.config.use_cache = True
    try:
        state_dict = full_model_state_dict(model) if is_fsdp_model(model) else None
        is_main = distributed is None or distributed.is_main
        if is_main:
            destination.mkdir(parents=True, exist_ok=True)
            if is_qwen35_composite_text_model(raw_model):
                # Keep checkpoints simultaneously usable by:
                #   1. AutoModelForCausalLM, which extracts the text_config; and
                #   2. vLLM 0.17, which registers Qwen3.5's official composite
                #      architecture but not Qwen3_5ForCausalLM.
                # Only serialization names/config change. No vision parameters
                # are materialized, trained, or added to the optimizer.
                source_state = (
                    state_dict if state_dict is not None else raw_model.state_dict()
                )
                composite_state = {
                    qwen35_composite_weight_name(name): value
                    for name, value in source_state.items()
                }
                if len(composite_state) != len(source_state):
                    raise RuntimeError(
                        "Qwen3.5 composite checkpoint key mapping produced a collision"
                    )
                previous_tied_keys = getattr(raw_model, "_tied_weights_keys", None)
                # Qwen3.5-4B ties embeddings and lm_head. Tell safe serialization
                # the mapped alias so it does not reject the shared storage.
                raw_model._tied_weights_keys = {
                    "lm_head.weight": "model.language_model.embed_tokens.weight"
                }
                try:
                    raw_model.save_pretrained(
                        destination,
                        safe_serialization=True,
                        state_dict=composite_state,
                    )
                finally:
                    raw_model._tied_weights_keys = previous_tied_keys
                raw_model._b200_source_config.save_pretrained(destination)
            else:
                save_kwargs = (
                    {"state_dict": state_dict} if state_dict is not None else {}
                )
                raw_model.save_pretrained(
                    destination,
                    safe_serialization=True,
                    **save_kwargs,
                )
            tokenizer.save_pretrained(destination)
    finally:
        raw_model.config.use_cache = previous_use_cache
    if distributed is not None:
        distributed.barrier()


def _evaluate_vllm_subprocess(
    model,
    tokenizer,
    model_name: str,
    model_path: Path | None,
    step: int,
    config: dict[str, Any],
    resolved_config_path: Path,
    output_dir: Path,
    runtime_settings: dict[str, Any],
    *,
    distributed_rank: int = 0,
    distributed_world_size: int = 1,
    distributed_local_rank: int | None = None,
    abort_path: Path | None = None,
    timeout_sec: float | None = None,
) -> dict[str, Any]:
    if hasattr(model, "peft_config"):
        raise RuntimeError(
            "vLLM periodic evaluation currently requires full-parameter training; "
            "set training_evaluation.backend=hf when training.use_lora=true"
        )

    temporary_snapshot: tempfile.TemporaryDirectory[str] | None = None
    if model_path is None:
        if is_fsdp_model(model):
            raise RuntimeError(
                "FSDP periodic vLLM evaluation requires a collectively exported "
                "checkpoint/snapshot path"
            )
        snapshot_root = output_dir.parent / ".snapshots"
        snapshot_root.mkdir(parents=True, exist_ok=True)
        temporary_snapshot = tempfile.TemporaryDirectory(
            prefix=f"step-{step:06d}-", dir=snapshot_root
        )
        model_path = Path(temporary_snapshot.name)
        _save_inference_snapshot(model, tokenizer, model_path)

    repo_root = Path(__file__).resolve().parents[1]
    environment = isolate_distributed_subprocess_environment()
    environment["VLLM_LOGGING_LEVEL"] = environment.get("VLLM_LOGGING_LEVEL", "WARNING")
    environment["PYTHONUNBUFFERED"] = "1"
    environment["PYTHONPATH"] = os.pathsep.join(
        filter(None, (str(repo_root), environment.get("PYTHONPATH", "")))
    )
    evaluator_settings = dict(runtime_settings)
    if distributed_world_size > 1:
        evaluator_settings["_shard_rank"] = int(distributed_rank)
        evaluator_settings["_shard_world_size"] = int(distributed_world_size)
        evaluator_settings["vllm"] = {
            **dict(runtime_settings.get("vllm", {})),
            # One independent engine per training GPU. Never create a
            # cross-rank tensor-parallel vLLM process for periodic evaluation.
            "tensor_parallel_size": 1,
        }
        # Sharding is global-rank based, while device selection must be
        # local-rank based on multi-node launches.  On the usual single-node
        # run these are identical; separating them avoids mapping rank 2 to a
        # nonexistent third device on a two-GPU node.
        device_rank = (
            int(distributed_local_rank)
            if distributed_local_rank is not None
            else int(distributed_rank)
        )
        visible_devices = environment.get("CUDA_VISIBLE_DEVICES")
        if visible_devices:
            devices = [
                item.strip() for item in visible_devices.split(",") if item.strip()
            ]
            if len(devices) == 1:
                # Some schedulers pre-mask each worker to one physical GPU.
                # In that case the only visible device is already the correct
                # local target, regardless of local-rank numbering.
                environment["CUDA_VISIBLE_DEVICES"] = devices[0]
            elif device_rank >= len(devices):
                raise RuntimeError(
                    "Evaluation LOCAL_RANK is outside CUDA_VISIBLE_DEVICES: "
                    f"local_rank={device_rank}, devices={visible_devices!r}"
                )
            else:
                environment["CUDA_VISIBLE_DEVICES"] = devices[device_rank]
        else:
            environment["CUDA_VISIBLE_DEVICES"] = str(device_rank)
    command = [
        sys.executable,
        "-m",
        "b200_experiment.vllm_evaluation",
        "--config",
        str(resolved_config_path.resolve()),
        "--model",
        str(model_path.resolve()),
        "--name",
        model_name,
        "--output",
        str(output_dir.resolve()),
        "--settings-json",
        json.dumps(evaluator_settings),
    ]
    torch.cuda.empty_cache()
    try:
        if abort_path is None:
            # Preserve the original blocking single-GPU behavior while still
            # retaining a process handle for descendant cleanup on failure.
            process = subprocess.Popen(
                command,
                cwd=repo_root,
                env=environment,
                start_new_session=True,
            )
            try:
                return_code = process.wait()
            except BaseException:
                _terminate_process_group(process)
                raise
            if return_code != 0:
                # A failed vLLM launcher may leave EngineCore workers alive
                # even after its own exit.
                _terminate_process_group(process)
                raise subprocess.CalledProcessError(return_code, command)
        else:
            process = subprocess.Popen(
                command,
                cwd=repo_root,
                env=environment,
                # vLLM creates EngineCore/worker descendants. Keep them in a
                # dedicated session so abort/timeout cleanup cannot orphan GPU
                # allocations that break later evaluation.
                start_new_session=True,
            )
            started = time.monotonic()
            while process.poll() is None:
                if abort_path.is_file():
                    _terminate_process_group(process)
                    raise RuntimeError(
                        "Periodic evaluation aborted because another rank "
                        f"reported failure: {abort_path.read_text(encoding='utf-8')}"
                    )
                if (
                    timeout_sec is not None
                    and time.monotonic() - started >= timeout_sec
                ):
                    _terminate_process_group(process)
                    raise TimeoutError(
                        "Periodic evaluation subprocess exceeded the configured "
                        f"filesystem timeout of {timeout_sec:.1f}s"
                    )
                time.sleep(0.25)
            if process.returncode != 0:
                _terminate_process_group(process)
                raise subprocess.CalledProcessError(process.returncode, command)
        return json.loads((output_dir / "summary.json").read_text(encoding="utf-8"))
    finally:
        if temporary_snapshot is not None:
            temporary_snapshot.cleanup()


def _atomic_evaluation_json(path: Path, payload: dict[str, Any]) -> None:
    """Publish a small evaluation coordination record atomically."""
    path.parent.mkdir(parents=True, exist_ok=True)
    temporary = path.with_name(f".{path.name}.tmp-{os.getpid()}-{time.time_ns()}")
    temporary.write_text(
        json.dumps(payload, indent=2, ensure_ascii=False) + "\n", encoding="utf-8"
    )
    os.replace(temporary, path)


def _read_evaluation_json(path: Path) -> dict[str, Any] | None:
    try:
        return json.loads(path.read_text(encoding="utf-8"))
    except FileNotFoundError:
        return None


def _evaluation_sync_timeout(settings: dict[str, Any]) -> float:
    timeout = float(settings.get("sync_timeout_sec", 24 * 60 * 60))
    if timeout <= 0:
        raise ValueError("training_evaluation.sync_timeout_sec must be positive")
    return timeout


def _wait_for_evaluation_signal(
    coordination_dir: Path,
    timeout: float,
    *,
    signal_names: tuple[str, ...],
) -> tuple[str, dict[str, Any]]:
    deadline = time.monotonic() + timeout
    while True:
        abort = _read_evaluation_json(coordination_dir / "abort.json")
        if abort is not None:
            raise RuntimeError(
                "Periodic evaluation failed on another rank: "
                f"{abort.get('error', abort)}"
            )
        for name in signal_names:
            payload = _read_evaluation_json(coordination_dir / name)
            if payload is not None:
                return name, payload
        if time.monotonic() >= deadline:
            raise TimeoutError(
                "Timed out waiting for filesystem-synchronized periodic evaluation "
                f"signal in {coordination_dir} after {timeout:.1f}s"
            )
        time.sleep(0.25)


def _probe_base_evaluation_cache(
    *,
    config: dict[str, Any],
    runtime_settings: dict[str, Any],
    model_path: Path,
    model_name: str,
    destination: Path,
    cache_dir: str | Path | None,
) -> tuple[dict[str, Any], str] | None:
    """Read-only cache probe used before deciding whether to shard evaluation."""
    cache_key = base_evaluation_cache_key(config, runtime_settings, model_path)
    cache_entry = resolve_base_cache_root(config, cache_dir) / cache_key
    local = load_compatible_evaluation(
        destination,
        model_path,
        runtime_settings,
        expected_cache_key=cache_key,
    )
    if local is not None:
        return local, "local"
    cached = load_compatible_evaluation(
        cache_entry,
        model_path,
        runtime_settings,
        expected_cache_key=cache_key,
    )
    if cached is None:
        return None
    return materialize_evaluation(
        cache_entry, destination, model_name=model_name
    ), "shared"


def _run_distributed_vllm_evaluation(
    *,
    model,
    tokenizer,
    method: str,
    step: int,
    config: dict[str, Any],
    output_dir: Path,
    resolved_config_path: Path,
    checkpoint: Path | None,
    runtime_settings: dict[str, Any],
    distributed: DistributedContext,
) -> tuple[dict[str, Any], str, float]:
    """Run one independent TP=1 evaluator per rank without long NCCL waits."""
    settings = config.get("training_evaluation", {})
    eval_root = output_dir / str(settings.get("output_subdir", "training_eval"))
    step_dir = eval_root / f"step-{step:06d}"
    coordination_dir = eval_root / f".distributed-step-{step:06d}"
    rank_dir = step_dir / f".rank-{distributed.rank:05d}"
    timeout = _evaluation_sync_timeout(settings)
    method_name = METHOD_DISPLAY_NAMES[method]
    model_name = "Base student" if step == 0 else f"{method_name} step {step}"
    source_path = (
        Path(config["models"]["student_path"]).resolve() if step == 0 else checkpoint
    )
    if source_path is None:
        raise RuntimeError("Distributed vLLM evaluation requires a model snapshot path")

    cache_result: tuple[dict[str, Any], str] | None = None
    if distributed.is_main:
        try:
            if step == 0 and bool(settings.get("reuse_base_evaluation", True)):
                cache_result = _probe_base_evaluation_cache(
                    config=config,
                    runtime_settings=runtime_settings,
                    model_path=source_path,
                    model_name=model_name,
                    destination=step_dir,
                    cache_dir=settings.get("base_cache_dir"),
                )
            if cache_result is None:
                if step_dir.exists():
                    shutil.rmtree(step_dir)
                step_dir.mkdir(parents=True, exist_ok=True)
                if coordination_dir.exists():
                    shutil.rmtree(coordination_dir)
                coordination_dir.mkdir(parents=True, exist_ok=True)
                _atomic_evaluation_json(
                    coordination_dir / "start.json",
                    {"state": "start", "world_size": distributed.world_size},
                )
            else:
                if step == 0:
                    # Preserve the existing cache publisher/manifest behavior
                    # for both local and shared hits.  A shared hit was already
                    # materialized by the read-only probe, but routing it
                    # through the normal helper also writes the destination
                    # manifest used by later resume/cache probes.
                    local_suite, _ = evaluate_or_reuse_base(
                        config=config,
                        runtime_settings=runtime_settings,
                        model_path=source_path,
                        model_name=model_name,
                        destination=step_dir,
                        evaluator=lambda: cache_result[0],
                        cache_dir=settings.get("base_cache_dir"),
                        reuse_destination=True,
                    )
                    cache_result = (local_suite, "local")
                for stale_rank_dir in step_dir.glob(".rank-*"):
                    shutil.rmtree(stale_rank_dir, ignore_errors=True)
                if coordination_dir.exists():
                    shutil.rmtree(coordination_dir)
                coordination_dir.mkdir(parents=True, exist_ok=True)
                _atomic_evaluation_json(
                    coordination_dir / "result.json",
                    {
                        "state": "success",
                        "summary": str((step_dir / "summary.json").resolve()),
                        "cache_status": cache_result[1],
                        "evaluation_time": 0.0,
                    },
                )
        except Exception as exc:
            coordination_dir.mkdir(parents=True, exist_ok=True)
            _atomic_evaluation_json(
                coordination_dir / "abort.json",
                {"state": "error", "rank": distributed.rank, "error": repr(exc)},
            )
            raise
    else:
        signal_name, signal = _wait_for_evaluation_signal(
            coordination_dir,
            timeout,
            signal_names=("start.json", "result.json"),
        )
        if signal_name == "result.json":
            suite = json.loads(Path(signal["summary"]).read_text(encoding="utf-8"))
            _atomic_evaluation_json(
                coordination_dir / f"ack-{distributed.rank:05d}.json",
                {"state": "ack", "rank": distributed.rank},
            )
            return (
                suite,
                str(signal.get("cache_status")),
                float(signal.get("evaluation_time", 0.0)),
            )

    if distributed.is_main and cache_result is not None:
        try:
            _atomic_evaluation_json(
                coordination_dir / "ack-00000.json",
                {"state": "ack", "rank": 0},
            )
            deadline = time.monotonic() + timeout
            while not all(
                _read_evaluation_json(coordination_dir / f"ack-{rank:05d}.json")
                is not None
                for rank in range(distributed.world_size)
            ):
                if time.monotonic() >= deadline:
                    raise TimeoutError(
                        "Timed out waiting for cached evaluation acknowledgements"
                    )
                time.sleep(0.25)
            shutil.rmtree(coordination_dir, ignore_errors=True)
            return cache_result[0], cache_result[1], 0.0
        except Exception as exc:
            _atomic_evaluation_json(
                coordination_dir / "abort.json",
                {"state": "error", "rank": 0, "error": repr(exc)},
            )
            raise

    if cache_result is None:
        started = time.perf_counter()
        _atomic_evaluation_json(
            coordination_dir / f"rank-{distributed.rank:05d}.json",
            {"state": "running", "rank": distributed.rank},
        )
        try:
            _evaluate_vllm_subprocess(
                model,
                tokenizer,
                model_name,
                source_path,
                step,
                config,
                resolved_config_path,
                rank_dir,
                runtime_settings,
                distributed_rank=distributed.rank,
                distributed_world_size=distributed.world_size,
                distributed_local_rank=getattr(distributed, "local_rank", None),
                abort_path=coordination_dir / "abort.json",
                timeout_sec=timeout,
            )
            _atomic_evaluation_json(
                coordination_dir / f"rank-{distributed.rank:05d}.json",
                {
                    "state": "success",
                    "rank": distributed.rank,
                    "summary": str((rank_dir / "summary.json").resolve()),
                },
            )
        except Exception as exc:
            _atomic_evaluation_json(
                coordination_dir / f"rank-{distributed.rank:05d}.json",
                {"state": "error", "rank": distributed.rank, "error": repr(exc)},
            )
            _atomic_evaluation_json(
                coordination_dir / "abort.json",
                {"state": "error", "rank": distributed.rank, "error": repr(exc)},
            )
            raise
    if not distributed.is_main:
        signal_name, signal = _wait_for_evaluation_signal(
            coordination_dir,
            timeout,
            signal_names=("result.json",),
        )
        del signal_name
        suite = json.loads(Path(signal["summary"]).read_text(encoding="utf-8"))
        _atomic_evaluation_json(
            coordination_dir / f"ack-{distributed.rank:05d}.json",
            {"state": "ack", "rank": distributed.rank},
        )
        return (
            suite,
            str(signal.get("cache_status")),
            float(signal.get("evaluation_time", 0.0)),
        )

    try:
        rank_states: list[dict[str, Any]] = []
        deadline = time.monotonic() + timeout
        while len(rank_states) < distributed.world_size:
            abort = _read_evaluation_json(coordination_dir / "abort.json")
            if abort is not None:
                raise RuntimeError(
                    "Periodic evaluation failed on another rank: "
                    f"{abort.get('error', abort)}"
                )
            rank_states = []
            for rank in range(distributed.world_size):
                state = _read_evaluation_json(
                    coordination_dir / f"rank-{rank:05d}.json"
                )
                if state is not None:
                    if state.get("state") == "error":
                        raise RuntimeError(
                            f"Periodic evaluation rank {rank} failed: "
                            f"{state.get('error', state)}"
                        )
                    if state.get("state") == "success":
                        rank_states.append(state)
            if len(rank_states) == distributed.world_size:
                break
            if time.monotonic() >= deadline:
                raise TimeoutError(
                    "Timed out waiting for all periodic evaluation ranks after "
                    f"{timeout:.1f}s"
                )
            time.sleep(0.25)

        shard_dirs = [
            step_dir / f".rank-{rank:05d}" for rank in range(distributed.world_size)
        ]
        merged_suite = merge_vllm_evaluation_shards(
            model_name,
            source_path,
            config,
            step_dir,
            shard_dirs,
            runtime_settings,
        )
        cache_status = "generated"
        if step == 0 and bool(settings.get("reuse_base_evaluation", True)):
            # The merged destination is now a valid single-format evaluation;
            # reuse the existing cache publisher without running a second eval.
            merged_suite, _ = evaluate_or_reuse_base(
                config=config,
                runtime_settings=runtime_settings,
                model_path=source_path,
                model_name=model_name,
                destination=step_dir,
                evaluator=lambda: merged_suite,
                cache_dir=settings.get("base_cache_dir"),
                reuse_destination=True,
            )
        elapsed = time.perf_counter() - started
        _atomic_evaluation_json(
            coordination_dir / "result.json",
            {
                "state": "success",
                "summary": str((step_dir / "summary.json").resolve()),
                "cache_status": cache_status,
                "evaluation_time": elapsed,
            },
        )
        _atomic_evaluation_json(
            coordination_dir / "ack-00000.json",
            {"state": "ack", "rank": 0},
        )
        deadline = time.monotonic() + timeout
        while True:
            if all(
                _read_evaluation_json(coordination_dir / f"ack-{rank:05d}.json")
                is not None
                for rank in range(distributed.world_size)
            ):
                break
            if time.monotonic() >= deadline:
                raise TimeoutError(
                    "Timed out waiting for evaluation shard acknowledgements"
                )
            time.sleep(0.25)
        for shard_dir in shard_dirs:
            shutil.rmtree(shard_dir, ignore_errors=True)
        shutil.rmtree(coordination_dir, ignore_errors=True)
        return merged_suite, cache_status, elapsed
    except Exception as exc:
        _atomic_evaluation_json(
            coordination_dir / "abort.json",
            {"state": "error", "rank": 0, "error": repr(exc)},
        )
        raise


def _run_training_evaluation(
    model,
    tokenizer,
    method: str,
    step: int,
    max_steps: int,
    config: dict[str, Any],
    output_dir: Path,
    resolved_config_path: Path,
    checkpoint: Path | None = None,
    distributed: DistributedContext | None = None,
) -> dict[str, Any]:
    settings = config.get("training_evaluation", {})
    eval_root = output_dir / str(settings.get("output_subdir", "training_eval"))
    step_dir = eval_root / f"step-{step:06d}"
    runtime_settings = {
        "backend": str(settings.get("backend", "vllm")).lower(),
        "temperature": float(
            settings.get("temperature", config["evaluation"].get("temperature", 0.7))
        ),
        "top_p": float(settings.get("top_p", config["evaluation"].get("top_p", 0.95))),
        "num_responses": int(
            settings.get("num_responses", config["evaluation"].get("num_responses", 8))
        ),
        "batch_size": int(
            settings.get("batch_size", config["evaluation"].get("batch_size", 16))
        ),
        "max_new_tokens": int(
            settings.get(
                "max_new_tokens", config["evaluation"].get("max_new_tokens", 2048)
            )
        ),
        "limit": settings.get("limit", config["evaluation"].get("limit")),
        "metric": settings.get("metric", config["evaluation"].get("metric")),
        "benchmark_names": list(
            configured_benchmark_names(config, settings.get("benchmark_names"))
        ),
        "vllm": settings.get("vllm", {}),
    }
    started = time.perf_counter()
    method_name = METHOD_DISPLAY_NAMES[method]
    model_name = "Base student" if step == 0 else f"{method_name} step {step}"
    backend = runtime_settings["backend"]
    if distributed is not None and distributed.world_size > 1 and backend != "vllm":
        raise RuntimeError(
            "Multi-GPU training-time evaluation requires backend=vllm; "
            "HF evaluation remains available on a single GPU."
        )
    cache_status = "disabled"
    distributed_elapsed: float | None = None
    if backend == "vllm":
        source_path = (
            Path(config["models"]["student_path"]).resolve()
            if step == 0
            else checkpoint
        )

        def evaluate_vllm() -> dict[str, Any]:
            return _evaluate_vllm_subprocess(
                model,
                tokenizer,
                model_name,
                source_path,
                step,
                config,
                resolved_config_path,
                step_dir,
                runtime_settings,
            )

        if distributed is not None and distributed.world_size > 1:
            distributed_runtime_settings = {
                **runtime_settings,
                "vllm": {
                    **dict(runtime_settings.get("vllm", {})),
                    "tensor_parallel_size": 1,
                },
            }
            suite, cache_status, distributed_elapsed = _run_distributed_vllm_evaluation(
                model=model,
                tokenizer=tokenizer,
                method=method,
                step=step,
                config=config,
                output_dir=output_dir,
                resolved_config_path=resolved_config_path,
                checkpoint=checkpoint,
                runtime_settings=distributed_runtime_settings,
                distributed=distributed,
            )
        elif step == 0 and bool(settings.get("reuse_base_evaluation", True)):
            suite, cache_status = evaluate_or_reuse_base(
                config=config,
                runtime_settings=runtime_settings,
                model_path=source_path,
                model_name=model_name,
                destination=step_dir,
                evaluator=evaluate_vllm,
                cache_dir=settings.get("base_cache_dir"),
                reuse_destination=True,
            )
            if cache_status != "generated":
                skipped_responses = sum(
                    int(result["total"]) for result in suite["benchmarks"].values()
                )
                tqdm.write(
                    "Reused untouched-base avg@8 evaluation "
                    f"({cache_status} cache); skipped {skipped_responses:,} generations."
                )
        else:
            suite = evaluate_vllm()
    elif backend == "hf":
        suite = evaluate_loaded_suite(
            model,
            tokenizer,
            model_name,
            config,
            step_dir,
            runtime_settings=runtime_settings,
        )
    else:
        raise ValueError("training_evaluation.backend must be 'vllm' or 'hf'")
    torch.cuda.empty_cache()
    elapsed = (
        distributed_elapsed
        if distributed_elapsed is not None
        else time.perf_counter() - started
    )
    samples_per_problem = int(runtime_settings["num_responses"])
    metric_name = str(
        suite.get("parameters", {}).get(
            "metric", evaluation_metric_name(samples_per_problem)
        )
    )

    def history_for(history_metric: str) -> dict[str, Any]:
        benchmarks: dict[str, dict[str, Any]] = {}
        for name, result in suite["benchmarks"].items():
            if history_metric == "avg@8":
                selected_score = float(result["avg_at_8"])
            elif history_metric == "pass@8":
                selected_score = float(result["pass_at_8"])
            else:
                selected_score = float(result["accuracy"])
            benchmarks[name] = {
                "correct": result["correct"],
                "total": result["total"],
                # ``accuracy`` remains the selected score for compatibility
                # with plotting and legacy history readers.
                "accuracy": selected_score,
                "avg_at_n": selected_score,
                **(
                    {"avg_at_8": result["avg_at_8"]}
                    if "avg_at_8" in result
                    else {}
                ),
                **(
                    {
                        "pass_at_k": (
                            result["pass_at_8"]
                            if history_metric == "pass@8"
                            else result["pass_at_k"]
                        )
                    }
                    if history_metric == "pass@8" or "pass_at_k" in result
                    else {}
                ),
                **(
                    {"pass_at_8": result["pass_at_8"]}
                    if "pass_at_8" in result
                    else {}
                ),
                "problems": result.get("problems"),
                "samples_per_problem": result.get(
                    "samples_per_problem", samples_per_problem
                ),
                "metric": history_metric,
            }
        return {
            "step": step,
            "max_steps": max_steps,
            "method": method,
            "model_role": "base_student" if step == 0 else method,
            "backend": backend,
            "evaluation_time": elapsed,
            "base_cache_status": cache_status if step == 0 else None,
            "benchmarks": benchmarks,
            "parameters": {**suite["parameters"], "metric": history_metric},
            "details": str((step_dir / "summary.json").resolve()),
        }

    dual_metric_evaluation = metric_name in {"avg@8", "pass@8"} and all(
        "avg_at_8" in result and "pass_at_8" in result
        for result in suite["benchmarks"].values()
    )
    if dual_metric_evaluation:
        history_artifacts = (
            (
                "avg@8",
                output_dir / "eval_history.jsonl",
                output_dir / "eval_metrics.csv",
            ),
            (
                "pass@8",
                output_dir / "eval_history_pass_at_8.jsonl",
                output_dir / "eval_metrics_pass_at_8.csv",
            ),
        )
    else:
        history_artifacts = (
            (
                metric_name,
                output_dir / "eval_history.jsonl",
                output_dir / "eval_metrics.csv",
            ),
        )

    history_entries = {
        history_metric: history_for(history_metric)
        for history_metric, _, _ in history_artifacts
    }
    if distributed is None or distributed.is_main:
        for history_metric, history_path, _ in history_artifacts:
            _upsert_jsonl_row(
                history_path,
                history_entries[history_metric],
                ("step", "method"),
            )
    eval_metric_fields = (
        "step",
        "method",
        "backend",
        "benchmark",
        "correct",
        "total",
        "accuracy",
        "avg_at_n",
        "avg_at_8",
        "pass_at_k",
        "pass_at_8",
        "problems",
        "samples_per_problem",
        "metric",
        "evaluation_time_sec",
    )
    if distributed is None or distributed.is_main:
        for history_metric, _, metrics_path in history_artifacts:
            history_entry = history_entries[history_metric]
            for benchmark, result in history_entry["benchmarks"].items():
                _upsert_csv_row(
                    metrics_path,
                    {
                        "step": step,
                        "method": method,
                        "backend": backend,
                        "benchmark": benchmark,
                        **result,
                        "evaluation_time_sec": elapsed,
                    },
                    eval_metric_fields,
                    ("step", "method", "benchmark"),
                )
        if dual_metric_evaluation:
            tqdm.write(
                "Training evaluation reused one 8-response generation set for "
                "avg@8 and pass@8 histories."
            )
    if metric_name in history_entries:
        return history_entries[metric_name]
    return next(iter(history_entries.values()))


def _make_optimizer(parameters, training: dict[str, Any]):
    kwargs = dict(
        lr=float(training.get("learning_rate", 1e-5)),
        betas=tuple(training.get("adam_betas", [0.9, 0.95])),
        weight_decay=float(training.get("weight_decay", 0.0)),
    )
    if bool(training.get("fused_optimizer", True)):
        try:
            return torch.optim.AdamW(parameters, fused=True, **kwargs), True
        except (TypeError, RuntimeError):
            pass
    return torch.optim.AdamW(parameters, **kwargs), False


def _global_tensor_stats(
    values: torch.Tensor, distributed: DistributedContext
) -> dict[str, float]:
    """Globally reduce scalar statistics without gathering per-token tensors."""
    with torch.inference_mode():
        values = values.detach().float().reshape(-1)
        local_count = values.numel()
        local_sum = float(values.sum().item()) if local_count else 0.0
        local_square_sum = float(values.square().sum().item()) if local_count else 0.0
        local_min = float(values.min().item()) if local_count else float("inf")
        local_max = float(values.max().item()) if local_count else float("-inf")
    count = distributed.sum_int(local_count)
    if count <= 0:
        raise ValueError("Cannot summarize an empty global tensor")
    total = distributed.sum_float(local_sum)
    square_total = distributed.sum_float(local_square_sum)
    mean = total / count
    return {
        "mean": mean,
        "std": math.sqrt(max(square_total / count - mean * mean, 0.0)),
        "min": -distributed.max_float(-local_min),
        "max": distributed.max_float(local_max),
        "count": float(count),
    }


def _opd_train_step(
    model,
    optimizer,
    rollout,
    position_weights,
    opd_reference: TopKOPDReference,
    config,
    device,
    distributed: DistributedContext,
    objective_valid_mask: torch.Tensor | None = None,
    trajectory_active_mask: torch.Tensor | None = None,
    trajectory_group_ids: list[int] | tuple[int, ...] | torch.Tensor | None = None,
    gibbs_scores: torch.Tensor | None = None,
    gibbs_epsilon: float | None = None,
    gibbs_mode: str = "gibbs",
    gibbs_weight_min: float = 0.5,
    gibbs_weight_max: float = 2.0,
    gibbs_final_epsilon: float = 0.02,
    rollout_id: int = 0,
    ppo_minibatch_offset: int = 0,
    max_optimizer_steps: int | None = None,
    optimizer_step_start: int = 0,
    on_optimizer_step: Callable[[int, dict[str, float]], None] | None = None,
):
    training = config["training"]
    local_batch_size = rollout.input_ids.shape[0]
    if local_batch_size <= 0:
        raise ValueError("OPD train step received an empty local/global batch")
    eps_low, eps_high = (
        float(training.get("ppo_clip_low", 0.2)),
        float(training.get("ppo_clip_high", 0.28)),
    )
    # GRPO's standard clipped surrogate has no dual-clip term.  The existing
    # OPD/TA/RAC/CMT recipe keeps its historical dual clipping unchanged.
    dual_clip = (
        None
        if str(config.get("experiment", {}).get("method", "")).lower() in {"grpo", "iw"}
        else float(training.get("ppo_dual_clip", 3.0))
    )
    objective_valid = (
        rollout.valid_mask
        if objective_valid_mask is None
        else objective_valid_mask.to(device=rollout.valid_mask.device, dtype=torch.bool)
    )
    if objective_valid.shape != rollout.valid_mask.shape:
        raise ValueError("objective_valid_mask must align with rollout.valid_mask")
    if bool((objective_valid & ~rollout.valid_mask.bool()).any()):
        raise ValueError("Objective-valid tokens must also be valid rollout tokens")
    trajectory_active = (
        objective_valid.any(dim=-1)
        if trajectory_active_mask is None
        else trajectory_active_mask.to(
            device=rollout.valid_mask.device, dtype=torch.bool
        )
    )
    if trajectory_active.shape != (local_batch_size,):
        raise ValueError("trajectory_active_mask must have shape [local_batch]")
    active_positions = trajectory_active.nonzero(as_tuple=False).flatten()
    local_real_count = int(active_positions.numel())
    if local_real_count and not torch.equal(
        active_positions,
        torch.arange(local_real_count, device=active_positions.device),
    ):
        raise ValueError("Active local trajectories must form a contiguous prefix")
    counts = tuple(
        int(value) for value in distributed.all_gather_objects(local_real_count)
    )
    global_trajectory_count = sum(counts)
    if global_trajectory_count <= 0:
        raise ValueError("OPD train step received no active global trajectories")
    ppo_size = _ppo_mini_batch_size(training, global_trajectory_count)
    if ppo_size < distributed.world_size:
        raise ValueError(
            "training.ppo_mini_batch_size must be at least world size so every "
            "rank can receive a real trajectory in a complete PPO minibatch"
        )
    micro_batch = _micro_batch_size_per_gpu(training, distributed.world_size, ppo_size)
    ppo_count = _ppo_minibatch_count(global_trajectory_count, ppo_size)
    if (gibbs_scores is None) != (gibbs_epsilon is None):
        raise ValueError("gibbs_scores and gibbs_epsilon must be provided together")
    use_groupwise_gibbs = gibbs_scores is not None
    if gibbs_scores is not None and gibbs_scores.shape != objective_valid.shape:
        raise ValueError("gibbs_scores must align with the token-level objective mask")
    grouped_ids: tuple[tuple[int, ...], ...] | None = None
    local_group_ids: tuple[int, ...] = ()
    if trajectory_group_ids is not None:
        if torch.is_tensor(trajectory_group_ids):
            local_group_ids = tuple(
                int(value) for value in trajectory_group_ids.detach().cpu().tolist()
            )
        else:
            local_group_ids = tuple(int(value) for value in trajectory_group_ids)
        if len(local_group_ids) != local_batch_size:
            raise ValueError(
                "trajectory_group_ids must align with the local rollout batch"
            )
        grouped_ids = tuple(
            tuple(int(value) for value in values)
            for values in distributed.all_gather_objects(
                local_group_ids[:local_real_count]
            )
        )
        if tuple(len(values) for values in grouped_ids) != counts:
            raise AssertionError(
                "Grouped PPO metadata does not match active row counts"
            )
    offset = int(ppo_minibatch_offset)
    if not 0 <= offset < ppo_count:
        raise ValueError(
            f"ppo_minibatch_offset={offset} is invalid for {ppo_count} mini-batches"
        )
    remaining_limit = ppo_count - offset
    if max_optimizer_steps is not None:
        remaining_limit = min(remaining_limit, max(0, int(max_optimizer_steps)))
    if remaining_limit <= 0:
        raise ValueError("No PPO mini-batch remains for this optimizer call")
    model.train()
    unwrap_model(model).config.use_cache = False
    response_lengths = rollout.valid_mask.long().sum(dim=-1)
    fsdp_no_sync = bool(
        config.get("distributed", {}).get("fsdp", {}).get("use_no_sync", False)
    )
    may_skip_sync = isinstance(model, DistributedDataParallel) or (
        is_fsdp_model(model) and fsdp_no_sync
    )
    minibatch_metrics: list[dict[str, float]] = []
    allocated_position_weights = (
        torch.zeros_like(gibbs_scores, dtype=torch.float32)
        if use_groupwise_gibbs
        else None
    )
    allocated_raw_position_weights = (
        torch.zeros_like(gibbs_scores, dtype=torch.float32)
        if use_groupwise_gibbs
        else None
    )
    allocated_group_indices = (
        torch.full_like(gibbs_scores, -1, dtype=torch.long)
        if use_groupwise_gibbs
        else None
    )
    allocated_optimizer_steps = (
        torch.full_like(gibbs_scores, -1, dtype=torch.long)
        if use_groupwise_gibbs
        else None
    )
    allocated_processed_mask = (
        torch.zeros_like(gibbs_scores, dtype=torch.bool)
        if use_groupwise_gibbs
        else None
    )
    gibbs_allocation_count = 0
    gibbs_allocation_seconds = 0.0
    grouped_rows_seen: set[int] = set()
    for ppo_index in range(offset, min(ppo_count, offset + remaining_limit)):
        # PPO_MINI_BATCH_SIZE is global. CMT uses response-index-major groups;
        # other methods retain the deterministic rank-interleaved order.
        if grouped_ids is None:
            local_indices, global_minibatch_count = distributed_ppo_minibatch_partition(
                counts,
                distributed.rank,
                ppo_size,
                ppo_index,
            )
        else:
            local_indices, global_minibatch_count = grouped_ppo_minibatch_partition(
                grouped_ids,
                distributed.rank,
                ppo_size,
                ppo_index,
            )
            duplicate_rows = grouped_rows_seen.intersection(local_indices)
            if duplicate_rows:
                raise AssertionError(
                    f"Grouped PPO partition repeated local rows: {sorted(duplicate_rows)}"
                )
            grouped_rows_seen.update(local_indices)
        local_minibatch_count = len(local_indices)
        if distributed.any(local_minibatch_count == 0):
            raise ValueError(
                "Global PPO minibatch has no real trajectory on rank "
                f"{distributed.rank}: minibatch={ppo_index}, counts={counts}, "
                f"global_ppo_mini_batch_size={ppo_size}. Reduce world size or "
                "choose a PPO batch/data tail that gives every rank a real row."
            )
        padded_count = distributed.max_int(len(local_indices))
        filler = int(response_lengths.argmin().item()) if local_batch_size else 0
        row_active = [True] * len(local_indices)
        while len(local_indices) < padded_count:
            local_indices.append(filler)
            row_active.append(False)
        indices = torch.tensor(
            local_indices, dtype=torch.long, device=rollout.input_ids.device
        )
        active_rows = torch.tensor(
            row_active, dtype=torch.bool, device=rollout.input_ids.device
        )
        if (
            bool(training.get("length_bucketed_micro_batches", True))
            and micro_batch > 1
        ):
            lengths = response_lengths.index_select(0, indices)
            sort_values = torch.where(active_rows, lengths, -torch.ones_like(lengths))
            order = torch.argsort(sort_values, descending=True, stable=True)
            indices = indices.index_select(0, order)
            active_rows = active_rows.index_select(0, order)
        micro_indices = list(indices.split(micro_batch))
        micro_active = list(active_rows.split(micro_batch))
        ppo_valid = objective_valid.index_select(0, indices) & active_rows.unsqueeze(1)
        allocation_inverse_temperature = 0.0
        allocation_metrics = {
            "allocation_kl_pre_bound": 0.0,
            "allocation_kl_post_bound": 0.0,
            "weight_raw_max": 0.0,
            "weight_final_min": 0.0,
            "weight_final_max": 0.0,
            "fraction_at_weight_min": 0.0,
            "fraction_at_weight_max": 0.0,
            "normalized_ess": 0.0,
            "max_token_probability": 0.0,
            "allocation_beta": 0.0,
            "allocation_log_c": 0.0,
            "allocation_kl_target": 0.0,
            "allocation_kl_final": 0.0,
            "allocation_mean_weight_error": 0.0,
            "allocation_solver_status": "not_applicable",
            "allocation_maximum_feasible_kl": float("nan"),
        }
        allocation_started = time.perf_counter()
        if use_groupwise_gibbs:
            # The allocation domain is exactly this optimizer update's valid
            # token set.  It is neither the full rollout nor an individual
            # local rank/microbatch.
            local_group_scores = gibbs_scores.index_select(0, indices)[ppo_valid]
            (
                global_group_scores,
                group_start,
                group_end,
                _group_lengths,
            ) = distributed.all_gather_variable_1d(local_group_scores)
            if global_group_scores.numel() == 0:
                raise ValueError("CMT PPO group contains no valid tokens")
            (
                global_group_raw_weights,
                global_group_weights,
                allocation_inverse_temperature,
                allocation_metrics,
            ) = cmt_allocation(
                global_group_scores,
                float(gibbs_epsilon),
                mode=gibbs_mode,
                weight_min=gibbs_weight_min,
                weight_max=gibbs_weight_max,
                final_epsilon=gibbs_final_epsilon,
            )
            ppo_raw_weights = torch.zeros_like(
                gibbs_scores.index_select(0, indices), dtype=torch.float32
            )
            ppo_weights = torch.zeros_like(
                gibbs_scores.index_select(0, indices), dtype=torch.float32
            )
            ppo_raw_weights[ppo_valid] = global_group_raw_weights[group_start:group_end]
            ppo_weights[ppo_valid] = global_group_weights[group_start:group_end]
            finite_or_raise(
                "CMT groupwise raw Gibbs weights", ppo_raw_weights[ppo_valid]
            )
            finite_or_raise("CMT groupwise Gibbs weights", ppo_weights[ppo_valid])
            expected_group_mass = float(global_group_scores.numel())
            actual_group_mass = float(global_group_weights.sum().item())
            if not math.isclose(
                actual_group_mass,
                expected_group_mass,
                rel_tol=1e-5,
                abs_tol=1e-4,
            ):
                raise AssertionError(
                    "CMT Gibbs weights must have mean one within the PPO group"
                )
            real_indices = indices[active_rows]
            allocated_position_weights.index_copy_(
                0, real_indices, ppo_weights[active_rows]
            )
            allocated_raw_position_weights.index_copy_(
                0, real_indices, ppo_raw_weights[active_rows]
            )
            current_optimizer_step = optimizer_step_start + len(minibatch_metrics) + 1
            allocated_group_indices.index_fill_(0, real_indices, int(ppo_index))
            allocated_optimizer_steps.index_fill_(
                0, real_indices, int(current_optimizer_step)
            )
            allocated_processed_mask.index_copy_(
                0, real_indices, ppo_valid[active_rows]
            )
            gibbs_allocation_count += 1
        else:
            ppo_weights = position_weights.index_select(0, indices)
        gibbs_allocation_seconds += time.perf_counter() - allocation_started
        local_weight_mass = float(ppo_weights[ppo_valid].detach().float().sum().item())
        global_weight_mass = distributed.sum_float(local_weight_mass)
        optimizer.zero_grad(set_to_none=True)
        forward_seconds = backward_seconds = loss_value = 0.0
        base_loss_sum = 0.0
        local_clipped_candidates = local_candidate_count = 0
        local_ratio_sum = 0.0
        local_ratio_min = float("inf")
        local_ratio_max = float("-inf")
        for chunk_index, (chunk_indices, chunk_active) in enumerate(
            zip(micro_indices, micro_active)
        ):
            synchronize = chunk_index == len(micro_indices) - 1
            sync_context = (
                model.no_sync() if not synchronize and may_skip_sync else nullcontext()
            )
            with sync_context:
                cuda_sync(device)
                started = time.perf_counter()
                local_width = int(
                    response_lengths.index_select(0, chunk_indices).max().item()
                )
                start = rollout.prompt_width - 1
                input_stop = start + local_width
                input_ids = rollout.input_ids.index_select(0, chunk_indices)[
                    :, :input_stop
                ]
                attention_mask = rollout.attention_mask.index_select(0, chunk_indices)[
                    :, :input_stop
                ]
                forward_kwargs = {
                    "input_ids": input_ids,
                    "attention_mask": attention_mask,
                    "position_ids": position_ids_from_mask(attention_mask),
                    "use_cache": False,
                    "return_dict": True,
                }
                response_only_logits = supports_response_only_logits(model)
                if response_only_logits:
                    forward_kwargs["logits_to_keep"] = local_width
                output = model(**forward_kwargs)
                logits = (
                    output.logits[:, -local_width:]
                    if response_only_logits
                    else output.logits[:, start : start + local_width]
                )
                candidate_ids = opd_reference.candidate_ids.index_select(
                    0, chunk_indices
                )[:, :local_width]
                current = gather_candidate_log_probs(
                    logits,
                    candidate_ids,
                    temperature=float(config["rollout"].get("temperature", 1.0)),
                    chunk_steps=int(config["selector"].get("score_chunk_steps", 128)),
                    support_mask=(
                        None
                        if opd_reference.support_mask is None
                        else opd_reference.support_mask.index_select(0, chunk_indices)[
                            :, :local_width
                        ]
                    ),
                )
                chunk_reference = TopKOPDReference(
                    candidate_ids=candidate_ids,
                    old_student_log_probs=(
                        opd_reference.old_student_log_probs.index_select(
                            0, chunk_indices
                        )[:, :local_width]
                    ),
                    teacher_log_probs=opd_reference.teacher_log_probs.index_select(
                        0, chunk_indices
                    )[:, :local_width],
                    student_weights=opd_reference.student_weights.index_select(
                        0, chunk_indices
                    )[:, :local_width],
                    advantages=opd_reference.advantages.index_select(0, chunk_indices)[
                        :, :local_width
                    ],
                    support_mask=(
                        None
                        if opd_reference.support_mask is None
                        else opd_reference.support_mask.index_select(0, chunk_indices)[
                            :, :local_width
                        ]
                    ),
                )
                per_position_loss = topk_candidate_ppo_loss(
                    current,
                    chunk_reference,
                    clip_low=eps_low,
                    clip_high=eps_high,
                    dual_clip=dual_clip,
                )
                valid_chunk = objective_valid.index_select(0, chunk_indices)[
                    :, :local_width
                ] & chunk_active.unsqueeze(1)
                if use_groupwise_gibbs:
                    chunk_weights = allocated_position_weights.index_select(
                        0, chunk_indices
                    )[:, :local_width]
                else:
                    chunk_weights = position_weights.index_select(0, chunk_indices)[
                        :, :local_width
                    ]
                local_numerator, _ = weighted_token_sums(
                    per_position_loss, chunk_weights, valid_chunk
                )
                base_loss_sum += float(
                    per_position_loss.detach()[valid_chunk].float().sum().item()
                )
                with torch.no_grad():
                    ratio = torch.exp(
                        (
                            current.detach() - chunk_reference.old_student_log_probs
                        ).clamp(min=-20.0, max=20.0)
                    )
                    candidate_valid = valid_chunk.unsqueeze(-1).expand_as(ratio)
                    clipped = ratio.lt(1.0 - eps_low) | ratio.gt(1.0 + eps_high)
                    local_clipped_candidates += int(
                        (clipped & candidate_valid).sum().item()
                    )
                    ratio_values = ratio[candidate_valid]
                    local_candidate_count += ratio_values.numel()
                    if ratio_values.numel():
                        local_ratio_sum += float(ratio_values.sum().item())
                        local_ratio_min = min(
                            local_ratio_min, float(ratio_values.min().item())
                        )
                        local_ratio_max = max(
                            local_ratio_max, float(ratio_values.max().item())
                        )
                # Synchronized DDP/FSDP gradients are rank-averaged. This
                # factor therefore yields the exact global weighted-token mean
                # for this PPO mini-batch, independent of micro-batch splitting.
                normalizer = (
                    distributed.world_size / global_weight_mass
                    if global_weight_mass > 0.0
                    else 0.0
                )
                loss = local_numerator * normalizer
                cuda_sync(device)
                forward_seconds += time.perf_counter() - started
                finite_or_raise("OPD loss", loss.detach().reshape(1))
                cuda_sync(device)
                started = time.perf_counter()
                loss.backward()
                cuda_sync(device)
                backward_seconds += time.perf_counter() - started
                loss_value += float(loss.detach().item())
                del (
                    output,
                    logits,
                    current,
                    per_position_loss,
                    local_numerator,
                    loss,
                    input_ids,
                    attention_mask,
                    forward_kwargs,
                    candidate_ids,
                    chunk_weights,
                )
        gradient_norm = clip_grad_norm(model, float(training.get("max_grad_norm", 1.0)))
        cuda_sync(device)
        started = time.perf_counter()
        optimizer.step()
        cuda_sync(device)
        optimizer_seconds = time.perf_counter() - started
        optimizer.zero_grad(set_to_none=True)
        global_loss = distributed.sum_float(loss_value) / distributed.world_size
        global_base_loss_sum = distributed.sum_float(base_loss_sum)
        global_valid_tokens = distributed.sum_int(int(ppo_valid.sum().item()))
        global_clipped_candidates = distributed.sum_int(local_clipped_candidates)
        global_candidate_count = distributed.sum_int(local_candidate_count)
        global_ratio_mean = distributed.sum_float(local_ratio_sum) / max(
            global_candidate_count, 1
        )
        global_ratio_min = (
            -distributed.max_float(-local_ratio_min) if global_candidate_count else 1.0
        )
        global_ratio_max = (
            distributed.max_float(local_ratio_max) if global_candidate_count else 1.0
        )
        global_optimizer_step = optimizer_step_start + len(minibatch_metrics) + 1
        response_index_composition: dict[str, int] = {}
        if grouped_ids is not None:
            local_composition: dict[int, int] = {}
            for row_index in real_indices.detach().cpu().tolist():
                response_index = int(local_group_ids[row_index])
                local_composition[response_index] = (
                    local_composition.get(response_index, 0) + 1
                )
            for rank_composition in distributed.all_gather_objects(local_composition):
                for response_index, count in rank_composition.items():
                    key = str(int(response_index))
                    response_index_composition[key] = response_index_composition.get(
                        key, 0
                    ) + int(count)
        allocation_id = f"rollout-{int(rollout_id):06d}:ppo-{int(ppo_index):04d}"
        metric = {
            "loss": global_loss,
            "weighted_final_loss": global_loss,
            "base_topk_opd_loss": global_base_loss_sum / max(global_valid_tokens, 1),
            "unweighted_opd_loss": global_base_loss_sum / max(global_valid_tokens, 1),
            "gradient_norm": float(gradient_norm.detach().item()),
            "training_forward_time": forward_seconds,
            "backward_time": backward_seconds,
            "optimizer_time": optimizer_seconds,
            "global_weight_mass": global_weight_mass,
            "clip_fraction": global_clipped_candidates / max(global_candidate_count, 1),
            "ratio_mean": global_ratio_mean,
            "ratio_min": global_ratio_min,
            "ratio_max": global_ratio_max,
            "ppo_minibatch_index": float(ppo_index),
            "ppo_minibatch_trajectory_count": float(global_minibatch_count),
            "local_ppo_minibatch_trajectory_count": float(local_minibatch_count),
            "gibbs_allocations": float(int(use_groupwise_gibbs)),
            "allocation_kl_epsilon": (
                float(gibbs_epsilon) if use_groupwise_gibbs else 0.0
            ),
            # Backward-compatible alias. In direct mode this is the KL of the
            # final bounded weights, not the unbounded diagnostic reference.
            "allocation_kl_achieved": float(
                allocation_metrics["allocation_kl_final"]
            ),
            "allocation_inverse_temperature": float(allocation_inverse_temperature),
            "rollout_id": int(rollout_id),
            "optimizer_step": int(global_optimizer_step),
            "ppo_group_index": int(ppo_index),
            "group_valid_token_count": int(global_group_scores.numel())
            if use_groupwise_gibbs
            else 0,
            "response_index_composition": response_index_composition,
            "allocation_id": allocation_id,
            **allocation_metrics,
        }
        metric["allocation_group"] = {
            key: metric[key]
            for key in (
                "allocation_id",
                "rollout_id",
                "optimizer_step",
                "ppo_group_index",
                "group_valid_token_count",
                "response_index_composition",
                "allocation_beta",
                "allocation_log_c",
                "allocation_kl_target",
                "allocation_kl_final",
                "allocation_mean_weight_error",
                "fraction_at_weight_min",
                "fraction_at_weight_max",
                "normalized_ess",
                "max_token_probability",
                "allocation_solver_status",
            )
        }
        minibatch_metrics.append(metric)
        if on_optimizer_step is not None:
            on_optimizer_step(global_optimizer_step, metric)
    if use_groupwise_gibbs and gibbs_allocation_count != len(minibatch_metrics):
        raise AssertionError("CMT must execute exactly one Gibbs allocation per update")
    processed_all_groups = offset == 0 and len(minibatch_metrics) == ppo_count
    if grouped_ids is not None and processed_all_groups:
        expected_rows = set(range(local_real_count))
        if grouped_rows_seen != expected_rows:
            raise AssertionError(
                "Grouped PPO partition did not consume each local row once"
            )
    total_weight = sum(item["global_weight_mass"] for item in minibatch_metrics)
    if total_weight > 0:
        aggregate_loss = (
            sum(item["loss"] * item["global_weight_mass"] for item in minibatch_metrics)
            / total_weight
        )
    else:
        aggregate_loss = sum(item["loss"] for item in minibatch_metrics) / len(
            minibatch_metrics
        )
    result = dict(minibatch_metrics[-1])
    result.update(
        loss=aggregate_loss,
        weighted_final_loss=aggregate_loss,
        training_forward_time=sum(
            item["training_forward_time"] for item in minibatch_metrics
        ),
        backward_time=sum(item["backward_time"] for item in minibatch_metrics),
        optimizer_time=sum(item["optimizer_time"] for item in minibatch_metrics),
        global_weight_mass=total_weight,
        optimizer_steps=len(minibatch_metrics),
        gibbs_allocations=gibbs_allocation_count,
        gibbs_allocation_time=gibbs_allocation_seconds,
        allocated_position_weights=allocated_position_weights,
        allocated_raw_position_weights=allocated_raw_position_weights,
        allocated_group_indices=allocated_group_indices,
        allocated_optimizer_steps=allocated_optimizer_steps,
        allocated_processed_mask=allocated_processed_mask,
        minibatches=minibatch_metrics,
    )
    return result


def _save_checkpoint(
    model,
    tokenizer,
    optimizer,
    output_dir: Path,
    step: int,
    final: bool,
    save_optimizer: bool,
    distributed: DistributedContext,
):
    checkpoint = output_dir / ("final" if final else f"checkpoint-{step:06d}")
    temporary = output_dir / f".{checkpoint.name}.incomplete"

    def _error_payload(error: BaseException) -> dict[str, str]:
        """Return a small, pickle-safe error for rank-0 -> rank-N broadcast."""

        return {"type": type(error).__name__, "message": str(error)}

    def _raise_broadcast_error(payload: dict[str, str], phase: str) -> None:
        message = payload.get("message", "unknown checkpoint error")
        if payload.get("type") == "FileExistsError":
            # Preserve the historical exception type for callers which use it
            # to distinguish an already-completed checkpoint from an I/O error.
            raise FileExistsError(message)
        raise RuntimeError(f"Checkpoint {phase} failed: {message}")

    def _remove_path(path: Path) -> None:
        """Remove exactly one stale checkpoint path, including a symlink/file."""

        if path.is_symlink() or not path.is_dir():
            path.unlink()
        else:
            shutil.rmtree(path)

    # Only rank 0 is allowed to inspect or mutate checkpoint paths.  In the old
    # implementation every rank performed this check before the first barrier;
    # rank 0 could create ``temporary`` in the meantime and a slower rank then
    # incorrectly treated that expected in-progress directory as a collision.
    setup_error = None
    if distributed.is_main:
        try:
            # A complete checkpoint is immutable: never silently overwrite it.
            # ``is_symlink`` also catches a broken symlink, which ``exists``
            # intentionally reports as false.
            if checkpoint.exists() or checkpoint.is_symlink():
                raise FileExistsError(
                    f"Refusing to overwrite checkpoint path: {checkpoint}"
                )

            # A previous process may have died after creating the staging
            # directory.  It is not a usable checkpoint, so remove this exact
            # stale path and retry.  This is deliberately rank-0-only and never
            # touches a completed checkpoint.
            if temporary.exists() or temporary.is_symlink():
                print(
                    f"[checkpoint] removing stale temporary checkpoint: {temporary}",
                    flush=True,
                )
                _remove_path(temporary)
            temporary.mkdir(parents=True, exist_ok=False)
        except BaseException as error:
            setup_error = _error_payload(error)

    setup_error = distributed.broadcast_object(setup_error)
    if setup_error is not None:
        _raise_broadcast_error(setup_error, "preparation")

    try:
        # All ranks enter the snapshot/optimizer collectives only after rank 0
        # has successfully prepared the staging directory.
        distributed.barrier()
        _save_inference_snapshot(model, tokenizer, temporary, distributed)
        if save_optimizer:
            optimizer_state = (
                full_optimizer_state_dict(model, optimizer)
                if is_fsdp_model(model) or distributed.is_main
                else None
            )
            local_rng = {
                "torch_rng_state": torch.get_rng_state().cpu(),
                "cuda_rng_state": torch.cuda.get_rng_state(distributed.device).cpu(),
            }
            rng_states = distributed.all_gather_objects(local_rng)
            if distributed.is_main:
                torch.save(
                    {
                        "step": step,
                        "optimizer": optimizer_state,
                        "optimizer_format": (
                            "fsdp_full_v1" if is_fsdp_model(model) else "standard"
                        ),
                        "world_size": distributed.world_size,
                        "rng_states": rng_states,
                        # Retain legacy fields for older single-process loaders.
                        "torch_rng_state": rng_states[0]["torch_rng_state"],
                        "cuda_rng_state_all": [
                            state["cuda_rng_state"] for state in rng_states
                        ],
                    },
                    temporary / "optimizer.pt",
                )
        distributed.barrier()

        # Commit is another rank-0-only filesystem operation.  Broadcast its
        # result before the post-commit barrier so an I/O failure cannot leave
        # the other ranks waiting in NCCL forever.
        commit_error = None
        if distributed.is_main:
            try:
                os.replace(temporary, checkpoint)
            except BaseException as error:
                commit_error = _error_payload(error)
        commit_error = distributed.broadcast_object(commit_error)
        if commit_error is not None:
            _raise_broadcast_error(commit_error, "commit")
    except BaseException:
        if distributed.is_main and (temporary.exists() or temporary.is_symlink()):
            _remove_path(temporary)
        raise

    distributed.barrier()

    # Keep latest.json atomic as before, but propagate a rank-0 write failure
    # before the final synchronization for the same no-hang guarantee.
    latest_error = None
    if distributed.is_main:
        try:
            latest = output_dir / "latest.json"
            latest_temporary = output_dir / ".latest.json.tmp"
            latest_temporary.write_text(
                json.dumps(
                    {
                        "step": step,
                        "checkpoint": checkpoint.name,
                        "final": bool(final),
                    },
                    ensure_ascii=False,
                )
                + "\n",
                encoding="utf-8",
            )
            os.replace(latest_temporary, latest)
        except BaseException as error:
            latest_error = _error_payload(error)
    latest_error = distributed.broadcast_object(latest_error)
    if latest_error is not None:
        _raise_broadcast_error(latest_error, "latest-pointer update")
    distributed.barrier()
    return checkpoint


def _grpo_answer_value(record: dict[str, Any], configured_key: str) -> Any:
    """Resolve a GRPO answer across common math-dataset schemas.

    Competition-MATH uses ``answer`` while DAPO-Math-17k uses ``solution``
    and stores a duplicate answer under ``reward_model.ground_truth``.  The
    reward benchmark selects the grading family (math vs. GPQA); it is not a
    dataset-name switch and must not be used to guess this field.
    """

    def nonempty(value: Any) -> Any | None:
        if value is None:
            return None
        if isinstance(value, str) and not value.strip():
            return None
        return value

    def lookup(key: str) -> Any | None:
        current: Any = record
        for part in str(key).split("."):
            if not isinstance(current, dict) or part not in current:
                return None
            current = current[part]
        return nonempty(current)

    configured = lookup(configured_key)
    if configured is not None:
        return configured

    # Keep this fallback deliberately small and deterministic.  It lets one
    # GRPO launcher work for the shipped Competition-MATH and DAPO exports,
    # while an explicitly configured key still has precedence.
    for key in (
        "answer",
        "solution",
        "ground_truth",
        "reference_answer",
        "target",
        "final_answer",
        "reward_model.ground_truth",
    ):
        value = lookup(key)
        if value is not None:
            return value
    return None


def _grpo_group_advantages(
    rollout,
    tokenizer,
    batch_records: list[dict[str, Any]],
    active_trajectories: torch.Tensor,
    response_indices: list[int],
    group_size: int,
    device: torch.device,
    *,
    answer_key: str = "answer",
    benchmark: str | None = None,
    std_epsilon: float = 1.0e-8,
) -> tuple[torch.Tensor, torch.Tensor, dict[str, float]]:
    """Return outcome rewards and within-prompt GRPO advantages."""
    if group_size < 2:
        raise ValueError("GRPO requires rollout.num_responses (group size) >= 2")
    if len(batch_records) != rollout.response_ids.shape[0]:
        raise ValueError("GRPO records and rollout rows do not align")
    if len(response_indices) != len(batch_records):
        raise ValueError("GRPO response indices and rollout rows do not align")
    rewards = torch.zeros(
        rollout.response_ids.shape[0], dtype=torch.float32, device=device
    )
    for row, (record, is_active) in enumerate(
        zip(batch_records, active_trajectories.detach().bool().cpu().tolist())
    ):
        if not is_active:
            continue
        valid = rollout.valid_mask[row]
        response = tokenizer.decode(
            rollout.response_ids[row][valid].detach().cpu().tolist(),
            skip_special_tokens=True,
        )
        answer = _grpo_answer_value(record, answer_key)
        if answer is None:
            available = ", ".join(sorted(map(str, record))) or "<none>"
            raise KeyError(
                f"GRPO could not resolve answer field {answer_key!r}; "
                f"tried answer/solution/ground_truth aliases; available fields: {available}"
            )
        # grade_evaluation_response intentionally consumes the canonical
        # ``answer`` key.  Adapt only this ephemeral grading row, leaving the
        # original dataset record and checkpoint metadata unchanged.
        reward_record = record
        if record.get("answer") != answer:
            reward_record = dict(record)
            reward_record["answer"] = answer
        rewards[row] = float(
            grade_evaluation_response(response, reward_record, benchmark=benchmark)
        )
    if rewards.numel() % group_size:
        raise ValueError("GRPO rollout rows are not divisible by the group size")
    grouped = rewards.reshape(-1, group_size)
    means = grouped.mean(dim=-1, keepdim=True)
    # Use the population standard deviation for a finite group. This avoids a
    # small-group Bessel amplification and keeps equal-reward groups at zero;
    # the normalization convention is recorded in run metadata.
    std = grouped.std(dim=-1, keepdim=True, unbiased=False)
    safe_std = torch.where(std > float(std_epsilon), std, torch.ones_like(std))
    advantages = ((grouped - means) / (safe_std + float(std_epsilon))).reshape(-1)
    advantages = torch.where(
        active_trajectories.bool(), advantages, torch.zeros_like(advantages)
    )
    active_rewards = rewards[active_trajectories.bool()]
    active_advantages = advantages[active_trajectories.bool()]
    return (
        rewards,
        advantages,
        {
            "reward_mean": float(active_rewards.mean().item())
            if active_rewards.numel()
            else 0.0,
            "reward_std": float(active_rewards.std(unbiased=False).item())
            if active_rewards.numel()
            else 0.0,
            "reward_min": float(active_rewards.min().item())
            if active_rewards.numel()
            else 0.0,
            "reward_max": float(active_rewards.max().item())
            if active_rewards.numel()
            else 0.0,
            "advantage_mean": float(active_advantages.mean().item())
            if active_advantages.numel()
            else 0.0,
            "advantage_std": float(active_advantages.std(unbiased=False).item())
            if active_advantages.numel()
            else 0.0,
            "active_groups": float(
                active_trajectories.reshape(-1, group_size).any(dim=-1).sum().item()
            ),
        },
    )


def _run_grpo_training(
    config: dict[str, Any],
    command_line: list[str] | None,
    distributed: DistributedContext,
    device: torch.device,
    strategy: str,
) -> dict[str, Any]:
    """Teacher-free GRPO loop sharing production OPD infrastructure."""
    experiment, training = config["experiment"], config["training"]
    rollout_backend = str(config["rollout"].get("backend", "vllm")).lower()
    if rollout_backend not in {"vllm", "hf"}:
        raise ValueError("rollout.backend must be 'vllm' or 'hf'")
    if strategy == "fsdp" and rollout_backend != "vllm":
        raise RuntimeError("FSDP GRPO training requires rollout.backend=vllm")
    if strategy == "fsdp" and str(
        config["models"].get("dtype", "bfloat16")
    ).lower() not in {"bfloat16", "bf16"}:
        raise ValueError("FSDP GRPO training requires models.dtype=bfloat16")
    rollout_temperature = float(config["rollout"].get("temperature", 1.0))
    if abs(rollout_temperature - 1.0) > 1.0e-6:
        raise ValueError(
            "GRPO requires rollout.temperature=1.0 because rollout_log_probs "
            "are the untempered behavior-policy log-probabilities"
        )
    group_size = int(config["rollout"].get("num_responses", 1))
    if group_size < 2:
        raise ValueError("GRPO requires rollout.num_responses >= 2")
    batch_size = int(config["rollout"]["batch_size"])
    ppo_minibatch_size = _ppo_mini_batch_size(training, batch_size * group_size)
    micro_batch_size_per_gpu = _micro_batch_size_per_gpu(
        training, distributed.world_size, ppo_minibatch_size
    )
    if distributed.is_main:
        tqdm.write(
            _format_batch_layout(
                batch_layout(
                    batch_size,
                    group_size,
                    distributed.world_size,
                    micro_batch_size_per_gpu,
                    ppo_minibatch_size,
                ),
                strategy,
                config,
            )
        )
    seed = int(experiment.get("seed", 1234))
    seed_everything(seed)
    resume_checkpoint = resolve_resume_checkpoint(
        training.get("resume_from_checkpoint"), experiment.get("output_dir")
    )
    resume_config_validation = (
        validate_resume_config(
            resume_checkpoint,
            config,
            allow_mismatch=bool(training.get("resume_allow_config_mismatch", False)),
        )
        if resume_checkpoint is not None
        else None
    )
    output_dir = Path(experiment["output_dir"]).resolve()
    metrics_path = output_dir / "metrics.jsonl"
    if (
        resume_checkpoint is None
        and metrics_path.exists()
        and not bool(experiment.get("allow_existing_output", False))
    ):
        raise FileExistsError(f"Refusing to append to existing run: {metrics_path}")
    output_dir.mkdir(parents=True, exist_ok=True)
    resolved_config_path = output_dir / (
        "resolved_config.yaml"
        if resume_checkpoint is None
        else f"resolved_config.resume-{resume_checkpoint.name}.yaml"
    )
    if distributed.is_main:
        save_config(config, resolved_config_path)
        canonical_config = output_dir / "resolved_config.yaml"
        if resume_checkpoint is not None and not canonical_config.exists():
            save_config(config, canonical_config)
    distributed.barrier()

    setup_progress = tqdm(
        total=4,
        desc="Setup GRPO",
        unit="stage",
        dynamic_ncols=True,
        leave=False,
        disable=not distributed.is_main,
    )
    setup_progress.set_postfix_str("stage=load-data", refresh=True)
    records, data_files = read_records(
        config["data"]["path"], split=config["data"].get("split")
    )
    if not records:
        raise ValueError("Configured training dataset is empty")
    validate_prompt_records(records, config["data"])
    original_record_count = len(records)
    prompt_tokenizer = load_student_tokenizer(config)
    records, prompt_filter_summary = filter_overlong_prompt_records(
        records, prompt_tokenizer, config["data"]
    )
    del prompt_tokenizer
    if distributed.is_main:
        tqdm.write(f"GRPO dataset examples: {prompt_filter_summary['kept_count']}")
    setup_progress.update(1)
    setup_progress.set_postfix_str(
        f"stage=start-rollout-{rollout_backend}", refresh=True
    )
    rollout_engine: VLLMRolloutEngine | None = None
    if rollout_backend == "vllm":
        rollout_engine = VLLMRolloutEngine(
            config,
            output_dir,
            local_rank=distributed.local_rank,
            world_size=distributed.world_size,
            port=unique_free_port(distributed),
        )
        rollout_engine.start()
    setup_progress.update(1)
    setup_progress.set_postfix_str("stage=load-student", refresh=True)
    model_load_config = config
    if resume_checkpoint is not None:
        model_load_config = copy.deepcopy(config)
        model_load_config["models"]["student_path"] = str(resume_checkpoint)
    student, tokenizer, model_metadata = load_student_model(model_load_config, device)
    training_student = student
    if strategy == "fsdp":
        training_student = wrap_fsdp_model(student, config, distributed, role="student")
    elif strategy == "ddp":
        training_student = DistributedDataParallel(
            student,
            device_ids=[distributed.local_rank],
            output_device=distributed.local_rank,
            broadcast_buffers=False,
            find_unused_parameters=bool(
                config.get("distributed", {}).get("find_unused_parameters", False)
            ),
            gradient_as_bucket_view=bool(
                config.get("distributed", {}).get("gradient_as_bucket_view", True)
            ),
            static_graph=bool(config.get("distributed", {}).get("static_graph", True)),
            bucket_cap_mb=float(
                config.get("distributed", {}).get("bucket_cap_mb", 100)
            ),
        )
    setup_progress.update(1)
    setup_progress.set_postfix_str("stage=optimizer", refresh=True)
    optimizer, fused_optimizer = _make_optimizer(
        [
            parameter
            for parameter in training_student.parameters()
            if parameter.requires_grad
        ],
        training,
    )
    resume_state = (
        restore_optimizer(
            optimizer,
            resume_checkpoint,
            device,
            model=training_student,
            distributed=distributed,
        )
        if resume_checkpoint is not None
        else None
    )
    resume_step = resume_state.step if resume_state is not None else 0
    resume_history = None
    if resume_state is not None:
        if distributed.is_main:
            resume_history = validate_append_history(
                output_dir, resume_step, resume_state.checkpoint
            )
        distributed.barrier()
    if distributed.is_main:
        metadata = collect_metadata(
            Path(__file__).resolve().parents[1],
            command_line or sys.argv,
            model_metadata,
            config["data"]["path"],
            data_files,
        )
        metadata["method"] = "grpo"
        metadata["data_schema"] = {
            "rows": len(records),
            "original_rows": original_record_count,
            "prompt_filter": prompt_filter_summary,
            "columns": sorted(records[0]),
            "files": [str(path) for path in data_files],
            "split": config["data"].get("split"),
            "full_dataset": True,
        }
        metadata["distributed"] = {
            "strategy": strategy,
            "world_size": distributed.world_size,
            "global_batch_preserved": True,
            "teacher_used": False,
            "student_sharding_strategy": "FULL_SHARD" if strategy == "fsdp" else None,
        }
        metadata["grpo"] = {
            "group_size": group_size,
            "reward": "math_verify_outcome_or_normalized_boxed_answer",
            "critic": False,
            "reference_model": False,
            "loss": "clipped_sampled_action_ppo",
            "advantage_normalization": "group_mean_population_std",
            "temperature": rollout_temperature,
        }
        metadata["resume"] = (
            {
                "checkpoint": str(resume_state.checkpoint),
                "optimizer_path": str(resume_state.optimizer_path),
                "step": resume_state.step,
                "history": resume_history,
                "config_validation": resume_config_validation,
            }
            if resume_state is not None
            else None
        )
        save_metadata(
            metadata,
            output_dir,
            filename=(
                "run_metadata.json"
                if resume_state is None
                else f"run_metadata.resume-step-{resume_step:06d}.json"
            ),
        )
    setup_progress.update(1)
    setup_progress.close()

    rollout_batches_per_epoch = math.ceil(len(records) / batch_size)
    optimizer_steps_per_epoch = _optimizer_steps_per_epoch(
        len(records), batch_size, group_size, ppo_minibatch_size
    )
    configured_max_steps = training.get("max_steps")
    max_steps = (
        int(configured_max_steps)
        if configured_max_steps is not None
        else int(training.get("epochs", 1)) * optimizer_steps_per_epoch
    )
    if resume_step >= max_steps:
        raise ValueError(
            f"Checkpoint is already at step {resume_step}, but configured total max_steps is {max_steps}"
        )
    training_eval_settings = config.get("training_evaluation", {})
    evaluation_steps = training_evaluation_steps(max_steps, training_eval_settings)
    if distributed.is_main and evaluation_steps:
        tqdm.write(
            "Periodic evaluation (GRPO): " + ", ".join(map(str, evaluation_steps))
        )
    tensorboard_logger = TensorBoardLogger(
        output_dir,
        dict(config.get("logging", {}).get("tensorboard", {})),
        enabled=distributed.is_main,
        resume_step=resume_step,
    )
    initial_evaluation = None
    if resume_step == 0 and should_run_training_evaluation(
        0, max_steps, training_eval_settings
    ):
        initial_evaluation = _run_training_evaluation(
            training_student,
            tokenizer,
            "grpo",
            0,
            max_steps,
            config,
            output_dir,
            resolved_config_path,
            distributed=distributed,
        )
        distributed.barrier()
    progress = tqdm(
        total=max_steps,
        desc="GRPO B200",
        unit="step",
        dynamic_ncols=True,
        leave=True,
        disable=not distributed.is_main,
        mininterval=0.5,
        initial=resume_step,
    )
    optimizer_step = resume_step
    rollout_index, ppo_minibatch_offset = _rollout_position_after_optimizer_steps(
        optimizer_step, len(records), batch_size, group_size, ppo_minibatch_size
    )
    answer_key = str(config.get("grpo", {}).get("answer_key", "answer"))
    reward_benchmark = config.get("grpo", {}).get("reward_benchmark")
    final_metrics: dict[str, Any] = {}
    while optimizer_step < max_steps:
        step_started = time.perf_counter()
        rollout_first_optimizer_step = optimizer_step + 1
        global_indices = epoch_batch_indices(
            len(records), batch_size, rollout_index, seed
        )
        rollout_ppo_minibatches = _ppo_minibatch_count(
            len(global_indices) * group_size, ppo_minibatch_size
        )
        local_start, _ = contiguous_partition(
            len(global_indices), distributed.rank, distributed.world_size
        )
        prompt_indices, active_prompts = padded_local_indices(
            global_indices, distributed.rank, distributed.world_size
        )
        prompt_records = [records[index] for index in prompt_indices]
        encoded, _ = tokenize_prompts(prompt_records, tokenizer, config["data"], device)
        encoded, indices, response_indices = expand_prompt_batch(
            encoded, prompt_indices, group_size
        )
        active_trajectories = torch.tensor(
            [active for active in active_prompts for _ in range(group_size)],
            dtype=torch.bool,
            device=device,
        )
        batch_records = [records[index] for index in indices]
        rollout_function = (
            rollout_engine.generate
            if rollout_engine is not None
            else generate_on_policy
        )
        rollout, rollout_time = _timed(
            device,
            rollout_function,
            training_student,
            encoded["input_ids"],
            encoded["attention_mask"],
            max_new_tokens=int(config["rollout"].get("max_new_tokens", 256)),
            temperature=rollout_temperature,
            top_p=float(config["rollout"].get("top_p", 1.0)),
            eos_token_ids=tokenizer.eos_token_id,
            pad_token_id=tokenizer.pad_token_id,
            seed=int(config["rollout"].get("seed", seed)),
            sample_seed_offset=rollout_index * batch_size * group_size
            + local_start * group_size,
        )
        for field in (
            "input_ids",
            "attention_mask",
            "response_ids",
            "valid_mask",
            "rollout_log_probs",
        ):
            setattr(rollout, field, getattr(rollout, field).clone())
        objective_valid = rollout.valid_mask & active_trajectories.unsqueeze(1)
        finite_or_raise(
            "GRPO rollout log-probs", rollout.rollout_log_probs[objective_valid]
        )
        _, advantages, reward_stats = _grpo_group_advantages(
            rollout,
            tokenizer,
            batch_records,
            active_trajectories,
            response_indices,
            group_size,
            device,
            answer_key=answer_key,
            benchmark=reward_benchmark,
            std_epsilon=float(config.get("grpo", {}).get("advantage_epsilon", 1.0e-8)),
        )
        response_lengths = objective_valid.long().sum(dim=-1).clamp_min(1)
        position_weights = torch.where(
            objective_valid,
            1.0 / response_lengths.unsqueeze(1).float(),
            torch.zeros_like(rollout.valid_mask, dtype=torch.float32),
        )
        with torch.inference_mode(False):
            old_log_probs = (
                torch.where(
                    rollout.valid_mask,
                    rollout.rollout_log_probs,
                    torch.zeros_like(rollout.rollout_log_probs),
                )
                .detach()
                .clone()
                .float()
                .unsqueeze(-1)
            )
            reference = TopKOPDReference(
                candidate_ids=rollout.response_ids.detach()
                .clone()
                .long()
                .unsqueeze(-1),
                old_student_log_probs=old_log_probs,
                teacher_log_probs=old_log_probs.clone(),
                student_weights=torch.ones_like(old_log_probs),
                # GRPO has one normalized outcome advantage per sampled
                # trajectory.  Keep it explicitly trajectory-level so it
                # broadcasts over every response token and the singleton
                # candidate dimension in topk_candidate_ppo_loss.
                advantages=advantages.detach().clone().float().reshape(-1, 1, 1),
                support_mask=None,
            )
        checkpoints_by_step: dict[int, Path] = {}
        evaluation_sources: dict[int, tuple[Path, bool]] = {}
        save_checkpoints = bool(training.get("save_checkpoints", True))
        save_interval = int(training.get("save_interval", 100))

        def after_optimizer_step(current_step: int, _metrics: dict[str, float]) -> None:
            should_evaluate = should_run_training_evaluation(
                current_step, max_steps, training_eval_settings
            )
            should_save = save_checkpoints and (
                current_step == max_steps
                or (save_interval > 0 and current_step % save_interval == 0)
            )
            checkpoint_path = None
            if should_save:
                checkpoint_path = _save_checkpoint(
                    training_student,
                    tokenizer,
                    optimizer,
                    output_dir,
                    current_step,
                    current_step == max_steps,
                    bool(training.get("save_optimizer", True)),
                    distributed,
                )
                checkpoints_by_step[current_step] = checkpoint_path
            if should_evaluate:
                evaluation_path = checkpoint_path
                temporary = False
                if evaluation_path is None:
                    evaluation_path = (
                        output_dir
                        / ".evaluation_snapshots"
                        / f"step-{current_step:06d}"
                    )
                    if distributed.is_main and evaluation_path.exists():
                        shutil.rmtree(evaluation_path)
                    distributed.barrier()
                    _save_inference_snapshot(
                        training_student, tokenizer, evaluation_path, distributed
                    )
                    temporary = True
                evaluation_sources[current_step] = (evaluation_path, temporary)
            if distributed.is_main:
                progress.update(1)

        train_metrics = _opd_train_step(
            training_student,
            optimizer,
            rollout,
            position_weights,
            reference,
            config,
            device,
            distributed,
            objective_valid_mask=objective_valid,
            trajectory_active_mask=active_trajectories,
            ppo_minibatch_offset=ppo_minibatch_offset,
            max_optimizer_steps=max_steps - optimizer_step,
            optimizer_step_start=optimizer_step,
            on_optimizer_step=after_optimizer_step,
        )
        optimizer_steps_completed = int(train_metrics["optimizer_steps"])
        optimizer_step += optimizer_steps_completed
        step = optimizer_step
        periodic_evaluations: dict[int, dict[str, Any]] = {}
        for evaluation_step, (evaluation_checkpoint, temporary) in sorted(
            evaluation_sources.items()
        ):
            evaluation_result = _run_training_evaluation(
                training_student,
                tokenizer,
                "grpo",
                evaluation_step,
                max_steps,
                config,
                output_dir,
                resolved_config_path,
                checkpoint=evaluation_checkpoint,
                distributed=distributed,
            )
            if distributed.is_main:
                periodic_evaluations[evaluation_step] = evaluation_result
            distributed.barrier()
            if distributed.is_main and temporary and evaluation_checkpoint.exists():
                shutil.rmtree(evaluation_checkpoint)
        valid_tokens = distributed.sum_int(int(objective_valid.sum().item()))
        trajectory_count = distributed.sum_int(int(active_trajectories.sum().item()))
        wall_time = distributed.max_float(time.perf_counter() - step_started)
        local_peak_allocated = torch.cuda.max_memory_allocated(device)
        local_peak_reserved = torch.cuda.max_memory_reserved(device)
        final_metrics = {
            "step": step,
            "epoch": rollout_index // rollout_batches_per_epoch,
            "step_in_epoch": rollout_index % rollout_batches_per_epoch,
            "rollout_batch_index": rollout_index,
            "rollout_first_optimizer_step": rollout_first_optimizer_step,
            "rollout_last_optimizer_step": step,
            "method": "grpo",
            "resumed_from": str(resume_state.checkpoint)
            if resume_state is not None
            else None,
            "resume_step": resume_step,
            "batch_size": len(global_indices),
            "prompt_batch_size": len(global_indices),
            "global_prompt_batch_size": len(global_indices),
            "local_prompt_batch_size": len(prompt_indices),
            "num_responses_per_prompt": group_size,
            "trajectory_batch_size": len(global_indices) * group_size,
            "global_trajectory_batch_size": len(global_indices) * group_size,
            "num_trajectories": trajectory_count,
            "ppo_mini_batch_size": ppo_minibatch_size,
            "local_ppo_mini_batch_size": (
                ppo_minibatch_size + distributed.world_size - 1
            )
            // distributed.world_size,
            "ppo_minibatches_in_rollout": optimizer_steps_completed,
            "micro_batch_size_per_gpu": micro_batch_size_per_gpu,
            "distributed_world_size": distributed.world_size,
            "distributed_strategy": strategy,
            "global_batch_preserved": True,
            "token_allocation_policy": "grpo_group_normalized_outcome_advantage",
            "objective_normalization": "global_sequence_mean",
            "grpo_group_size": group_size,
            "grpo_reward_mean": reward_stats["reward_mean"],
            "grpo_reward_std": reward_stats["reward_std"],
            "grpo_reward_min": reward_stats["reward_min"],
            "grpo_reward_max": reward_stats["reward_max"],
            "grpo_advantage_mean": reward_stats["advantage_mean"],
            "grpo_advantage_std": reward_stats["advantage_std"],
            "loss": train_metrics["loss"],
            "train_loss": train_metrics["loss"],
            "weighted_final_loss": train_metrics["weighted_final_loss"],
            "grpo_clip_fraction": train_metrics["clip_fraction"],
            "grpo_ratio_mean": train_metrics["ratio_mean"],
            "grpo_ratio_min": train_metrics["ratio_min"],
            "grpo_ratio_max": train_metrics["ratio_max"],
            "gradient_norm": distributed.max_float(train_metrics["gradient_norm"]),
            "grad_norm": distributed.max_float(train_metrics["gradient_norm"]),
            "training_forward_time": distributed.max_float(
                train_metrics["training_forward_time"]
            ),
            "backward_time": distributed.max_float(train_metrics["backward_time"]),
            "optimizer_time": distributed.max_float(train_metrics["optimizer_time"]),
            "lr": float(optimizer.param_groups[0]["lr"]),
            "rollout_time": distributed.max_float(rollout_time),
            "wall_clock_step_time": wall_time,
            "tokens_per_second": valid_tokens / max(wall_time, 1e-12),
            "generated_tokens_per_second": valid_tokens
            / max(distributed.max_float(rollout_time), 1e-12),
            "num_valid_tokens": valid_tokens,
            "mean_response_length": valid_tokens / max(trajectory_count, 1),
            "peak_gpu_allocated_bytes": distributed.max_int(local_peak_allocated),
            "peak_gpu_reserved_bytes": distributed.max_int(local_peak_reserved),
            "peak_gpu_allocated_gb": distributed.max_int(local_peak_allocated) / 2**30,
            "peak_gpu_reserved_gb": distributed.max_int(local_peak_reserved) / 2**30,
            "checkpoint": str(checkpoints_by_step[step])
            if step in checkpoints_by_step
            else None,
            "rollout_token_sha256": _rollout_hash(
                rollout.response_ids, objective_valid, distributed
            ),
        }
        training_events: list[dict[str, Any]] = []
        for event_offset, minibatch_metric in enumerate(train_metrics["minibatches"]):
            event_step = rollout_first_optimizer_step + event_offset
            event = copy.deepcopy(final_metrics)
            event.update(
                {
                    "step": event_step,
                    "train_loss": minibatch_metric["loss"],
                    "loss": minibatch_metric["loss"],
                    "weighted_final_loss": minibatch_metric["weighted_final_loss"],
                    "gradient_norm": distributed.max_float(
                        minibatch_metric["gradient_norm"]
                    ),
                    "grad_norm": distributed.max_float(
                        minibatch_metric["gradient_norm"]
                    ),
                    "grpo_clip_fraction": minibatch_metric["clip_fraction"],
                    "grpo_ratio_mean": minibatch_metric["ratio_mean"],
                    "grpo_ratio_min": minibatch_metric["ratio_min"],
                    "grpo_ratio_max": minibatch_metric["ratio_max"],
                    "ppo_minibatch_index": int(minibatch_metric["ppo_minibatch_index"]),
                    "ppo_minibatch_trajectory_count": int(
                        minibatch_metric["ppo_minibatch_trajectory_count"]
                    ),
                    "checkpoint": str(checkpoints_by_step[event_step])
                    if event_step in checkpoints_by_step
                    else None,
                }
            )
            if event_step in periodic_evaluations:
                periodic = periodic_evaluations[event_step]
                event["periodic_evaluation"] = {
                    "evaluation_time": periodic["evaluation_time"],
                    "benchmarks": periodic["benchmarks"],
                    "details": periodic["details"],
                }
            training_events.append(event)
        final_metrics = training_events[-1]
        if distributed.is_main:
            for event in training_events:
                _append_jsonl(metrics_path, event)
                _append_train_metrics_csv(output_dir / "train_metrics.csv", event)
                tensorboard_logger.write(event["step"], event, "grpo")
            progress.set_postfix(
                loss=f"{train_metrics['loss']:.4f}",
                reward=f"{reward_stats['reward_mean']:.3f}",
                refresh=True,
            )
        del (
            encoded,
            rollout,
            objective_valid,
            active_trajectories,
            reference,
            position_weights,
        )
        ppo_minibatch_offset += optimizer_steps_completed
        if ppo_minibatch_offset >= rollout_ppo_minibatches:
            rollout_index += 1
            ppo_minibatch_offset = 0
    progress.close()
    tensorboard_logger.close()
    if rollout_engine is not None:
        rollout_engine.close()
    distributed.barrier()
    summary = {
        "status": "ok",
        "method": "grpo",
        "steps": max_steps,
        "epochs": training.get("epochs"),
        "dataset_rows": len(records),
        "original_dataset_rows": original_record_count,
        "prompt_filter": prompt_filter_summary,
        "full_dataset": True,
        "ppo_mini_batch_size": ppo_minibatch_size,
        "optimizer_steps_per_epoch": optimizer_steps_per_epoch,
        "rollout_backend": rollout_backend,
        "resumed_from": str(resume_state.checkpoint)
        if resume_state is not None
        else None,
        "resume_step": resume_step,
        "distributed_world_size": distributed.world_size,
        "global_batch_preserved": True,
        "last": final_metrics,
        "student_path": model_metadata["student_path"],
        "teacher_path": None,
        "selector_score_dir": None,
        "evaluation_history": str((output_dir / "eval_history.jsonl").resolve())
        if bool(training_eval_settings.get("enabled", False))
        else None,
        "evaluation_history_pass_at_8": str(
            (output_dir / "eval_history_pass_at_8.jsonl").resolve()
        )
        if bool(training_eval_settings.get("enabled", False))
        and int(training_eval_settings.get("num_responses", 8)) == 8
        else None,
        "initial_evaluation": initial_evaluation,
    }
    if distributed.is_main:
        with (output_dir / "summary.json").open("w", encoding="utf-8") as handle:
            json.dump(summary, handle, indent=2, ensure_ascii=False, allow_nan=True)
            handle.write("\n")
    result = (
        summary
        if distributed.is_main
        else {"status": "worker_ok", "rank": distributed.rank}
    )
    distributed.close()
    return result


def run_training(
    config: dict[str, Any], command_line: list[str] | None = None
) -> dict[str, Any]:
    distributed_cfg = config.get("distributed", {})
    distributed = initialize_distributed(distributed_cfg.get("backend", "nccl"))
    device = distributed.device
    if (
        bool(config["experiment"].get("require_b200", True))
        and "B200" not in torch.cuda.get_device_name(device).upper()
    ):
        raise RuntimeError(
            f"This config requires NVIDIA B200; detected {torch.cuda.get_device_name(device)!r}"
        )
    torch.set_float32_matmul_precision("high")
    torch.backends.cuda.matmul.allow_tf32 = True
    experiment, training = config["experiment"], config["training"]
    strategy = distributed_strategy(config, distributed)
    method = str(experiment["method"]).lower()
    if method not in {"opd", "ta", "rac", "pgt", "cmt", "grpo", "iw"}:
        raise ValueError(
            "Training method must be opd, ta, rac, pgt, cmt, grpo, or iw, "
            f"got {method!r}"
        )
    if method == "grpo":
        return _run_grpo_training(config, command_line, distributed, device, strategy)
    if method == "cmt":
        rollout_temperature = float(config["rollout"].get("temperature", 1.0))
        rollout_top_p = float(config["rollout"].get("top_p", 1.0))
        if rollout_temperature <= 0.0 or not 0.0 < rollout_top_p <= 1.0:
            raise ValueError(
                "CMT rollout.temperature must be positive and rollout.top_p "
                "must lie in (0, 1]"
            )
        if rollout_top_p != 1.0:
            warnings.warn(
                "CMT's bounded truncated-kernel estimator is exact when the "
                "rollout samples the scored student distribution (top_p=1). "
                "With top_p<1 it remains bounded but is not unbiased for that "
                "kernel; continuing is an explicit diagnostic assumption rather "
                "than applying an invalid importance correction.",
                RuntimeWarning,
                stacklevel=2,
            )
    # Fail before starting vLLM or loading either model if a launch override
    # accidentally enables thinking or proposes a teacher tokenizer path.
    validate_shared_tokenizer_protocol(config)
    global_prompt_batch_size = int(config["rollout"]["batch_size"])
    num_responses = int(config["rollout"].get("num_responses", 1))
    ppo_mini_batch_size = _ppo_mini_batch_size(
        training, global_prompt_batch_size * num_responses
    )
    micro_batch_size_per_gpu = _micro_batch_size_per_gpu(
        training, distributed.world_size, ppo_mini_batch_size
    )
    layout = batch_layout(
        global_prompt_batch_size,
        num_responses,
        distributed.world_size,
        micro_batch_size_per_gpu,
        ppo_mini_batch_size,
    )
    configured_accumulation = training.get("grad_accum_steps", "auto")
    if configured_accumulation not in (None, "auto"):
        raise ValueError(
            "training.grad_accum_steps is derived automatically from each local "
            "trajectory batch. Configure training.micro_batch_size_per_gpu instead."
        )
    if distributed.is_main:
        tqdm.write(_format_batch_layout(layout, strategy, config))
    if strategy == "fsdp" and str(
        config["models"].get("dtype", "bfloat16")
    ).lower() not in {
        "bfloat16",
        "bf16",
    }:
        raise ValueError("FSDP production training requires models.dtype=bfloat16")
    opd_config = config.get("opd", {})
    top_k_strategy = str(opd_config.get("top_k_strategy", "only_stu"))
    reward_weight_mode = str(opd_config.get("reward_weight_mode", "student_p"))
    advantage_estimator = str(opd_config.get("adv_estimator", "token_reward_direct"))
    loss_aggregation = str(opd_config.get("loss_agg_mode", "token-mean"))
    controlled_settings = {
        "upstream_commit": (
            str(opd_config.get("upstream_commit", UPSTREAM_OPD_COMMIT)),
            UPSTREAM_OPD_COMMIT,
        ),
        "top_k_strategy": (top_k_strategy, UPSTREAM_TOP_K_STRATEGY),
        "reward_weight_mode": (reward_weight_mode, UPSTREAM_REWARD_WEIGHT_MODE),
        "adv_estimator": (advantage_estimator, UPSTREAM_ADV_ESTIMATOR),
        "loss_agg_mode": (loss_aggregation, UPSTREAM_LOSS_AGG_MODE),
    }
    incompatible = {
        key: actual
        for key, (actual, expected) in controlled_settings.items()
        if actual != expected
    }
    if incompatible:
        raise ValueError(
            "This controlled experiment supports only the pinned thunlp/OPD "
            f"recipe; incompatible settings: {incompatible}"
        )
    configured_top_k = int(config["selector"].get("top_k", DEFAULT_OPD_TOP_K))
    if configured_top_k <= 0:
        raise ValueError("selector.top_k must be positive")
    cmt_allocation_mode, cmt_weight_min, cmt_weight_max = validate_cmt_allocation(
        config["selector"].get("cmt_allocation_mode", "gibbs"),
        config["selector"].get("cmt_weight_min", 0.5),
        config["selector"].get("cmt_weight_max", 2.0),
    )
    cmt_correction_mode, cmt_correction_quantile = validate_cmt_correction(
        config["selector"].get("cmt_correction_mode", "none"),
        config["selector"].get("cmt_correction_quantile", 0.99),
    )
    cmt_final_allocation_kl = float(
        config["selector"].get("cmt_final_allocation_kl", 0.02)
    )
    if not math.isfinite(cmt_final_allocation_kl) or cmt_final_allocation_kl < 0.0:
        raise ValueError("selector.cmt_final_allocation_kl must be finite and >= 0")
    seed = int(experiment.get("seed", 1234))
    seed_everything(seed)
    resume_checkpoint = resolve_resume_checkpoint(
        training.get("resume_from_checkpoint"), experiment.get("output_dir")
    )
    resume_config_validation = (
        validate_resume_config(
            resume_checkpoint,
            config,
            allow_mismatch=bool(training.get("resume_allow_config_mismatch", False)),
        )
        if resume_checkpoint is not None
        else None
    )
    output_dir = Path(experiment["output_dir"]).resolve()
    metrics_path = output_dir / "metrics.jsonl"
    if (
        resume_checkpoint is None
        and metrics_path.exists()
        and not bool(experiment.get("allow_existing_output", False))
    ):
        raise FileExistsError(f"Refusing to append to existing run: {metrics_path}")
    output_dir.mkdir(parents=True, exist_ok=True)
    resolved_config_path = output_dir / (
        "resolved_config.yaml"
        if resume_checkpoint is None
        else f"resolved_config.resume-{resume_checkpoint.name}.yaml"
    )
    if distributed.is_main:
        save_config(config, resolved_config_path)
        canonical_config = output_dir / "resolved_config.yaml"
        if resume_checkpoint is not None and not canonical_config.exists():
            save_config(config, canonical_config)
    distributed.barrier()

    rollout_backend = str(config["rollout"].get("backend", "vllm")).lower()
    if rollout_backend not in {"vllm", "hf"}:
        raise ValueError("rollout.backend must be 'vllm' or 'hf'")
    if rollout_backend == "vllm" and bool(training.get("use_lora", False)):
        raise RuntimeError(
            "vLLM CUDA-IPC rollout requires full-parameter training; "
            "set training.use_lora=false or rollout.backend=hf"
        )
    if strategy == "fsdp" and rollout_backend != "vllm":
        raise RuntimeError(
            "FSDP training requires the per-rank vLLM rollout backend. The HF "
            "autoregressive fallback can finish at different times on each rank "
            "and is not collective-safe."
        )
    if (
        strategy == "fsdp"
        and bool(config.get("training_evaluation", {}).get("enabled", False))
        and str(config["training_evaluation"].get("backend", "vllm")).lower() != "vllm"
    ):
        raise RuntimeError(
            "FSDP periodic evaluation must use backend=vllm so rank 0 evaluates "
            "a collectively exported HF snapshot."
        )
    if (
        distributed.world_size > 1
        and bool(config.get("training_evaluation", {}).get("enabled", False))
        and str(config["training_evaluation"].get("backend", "vllm")).lower() != "vllm"
    ):
        raise RuntimeError(
            "Multi-GPU periodic evaluation requires backend=vllm so each rank "
            "can run an independent tensor_parallel_size=1 evaluator."
        )
    rollout_engine: VLLMRolloutEngine | None = None

    setup_progress = tqdm(
        total=4,
        desc=f"Setup {METHOD_DISPLAY_NAMES[method]}",
        unit="stage",
        dynamic_ncols=True,
        leave=False,
        disable=not distributed.is_main,
    )
    setup_progress.set_postfix_str("stage=load-data", refresh=True)
    records, data_files = read_records(
        config["data"]["path"], split=config["data"].get("split")
    )
    if not records:
        raise ValueError("Configured training dataset is empty")
    validate_prompt_records(records, config["data"])
    original_record_count = len(records)
    prompt_tokenizer = load_student_tokenizer(config)
    records, prompt_filter_summary = filter_overlong_prompt_records(
        records, prompt_tokenizer, config["data"]
    )
    del prompt_tokenizer
    if distributed.is_main:
        tqdm.write(f"Dataset examples: {prompt_filter_summary['original_count']}")
        tqdm.write(f"Kept: {prompt_filter_summary['kept_count']}")
        tqdm.write(
            "Filtered over MAX_PROMPT_LEN="
            f"{prompt_filter_summary['max_prompt_tokens']}: "
            f"{prompt_filter_summary['filtered_overlong_count']} "
            f"({prompt_filter_summary['filtered_overlong_percentage']:.2f}%)"
        )
        tqdm.write(
            "Maximum observed rendered prompt length: "
            f"{prompt_filter_summary['maximum_observed_prompt_length']} tokens"
        )
    setup_progress.update(1)
    setup_progress.set_postfix_str(
        f"stage=start-rollout-{rollout_backend}", refresh=True
    )
    if rollout_backend == "vllm":
        rollout_engine = VLLMRolloutEngine(
            config,
            output_dir,
            local_rank=distributed.local_rank,
            world_size=distributed.world_size,
            port=unique_free_port(distributed),
        )
        rollout_engine.start()
    setup_progress.update(1)
    setup_progress.set_postfix_str("stage=load-models", refresh=True)
    model_load_config = config
    if resume_checkpoint is not None:
        model_load_config = copy.deepcopy(config)
        model_load_config["models"]["student_path"] = str(resume_checkpoint)
    student, teacher, tokenizer, model_metadata = load_models(model_load_config, device)
    training_student = student
    scoring_teacher = teacher
    if strategy == "fsdp":
        training_student = wrap_fsdp_model(
            student,
            config,
            distributed,
            role="student",
        )
        scoring_teacher = wrap_fsdp_model(
            teacher,
            config,
            distributed,
            role="teacher",
        )
    elif strategy == "ddp":
        training_student = DistributedDataParallel(
            student,
            device_ids=[distributed.local_rank],
            output_device=distributed.local_rank,
            broadcast_buffers=False,
            find_unused_parameters=bool(
                distributed_cfg.get("find_unused_parameters", False)
            ),
            gradient_as_bucket_view=bool(
                distributed_cfg.get("gradient_as_bucket_view", True)
            ),
            static_graph=bool(distributed_cfg.get("static_graph", True)),
            bucket_cap_mb=float(distributed_cfg.get("bucket_cap_mb", 100)),
        )
    setup_progress.update(1)
    setup_progress.set_postfix_str("stage=optimizer", refresh=True)
    optimizer, fused_optimizer = _make_optimizer(
        [
            parameter
            for parameter in training_student.parameters()
            if parameter.requires_grad
        ],
        training,
    )
    resume_state = (
        restore_optimizer(
            optimizer,
            resume_checkpoint,
            device,
            model=training_student,
            distributed=distributed,
        )
        if resume_checkpoint is not None
        else None
    )
    resume_step = resume_state.step if resume_state is not None else 0
    resume_history = None
    if resume_state is not None:
        if distributed.is_main:
            resume_history = validate_append_history(
                output_dir, resume_step, resume_state.checkpoint
            )
        distributed.barrier()
    if distributed.is_main:
        metadata = collect_metadata(
            Path(__file__).resolve().parents[1],
            command_line or sys.argv,
            model_metadata,
            config["data"]["path"],
            data_files,
        )
        metadata["data_schema"] = {
            "rows": len(records),
            "original_rows": original_record_count,
            "prompt_filter": prompt_filter_summary,
            "columns": sorted(records[0]),
            "files": [str(path) for path in data_files],
            "split": config["data"].get("split"),
            "full_dataset": True,
        }
        metadata["distributed"] = {
            "strategy": strategy,
            "world_size": distributed.world_size,
            "global_batch_preserved": True,
            "global_ta_normalization": method in {"ta", "rac"},
            "global_token_budget": method in {"ta", "pgt"},
            "global_rac_weight_normalization": method == "rac",
            "global_cmt_kl_allocation": method == "cmt",
            "uniform_full_response_mask": method == "opd",
            "student_sharding_strategy": ("FULL_SHARD" if strategy == "fsdp" else None),
            "teacher_sharding_strategy": (
                "FULL_SHARD" if strategy == "fsdp" else "replicated"
            ),
            "teacher_cpu_offload": bool(
                distributed_cfg.get("fsdp", {}).get("teacher_cpu_offload", False)
            ),
        }
        if method == "cmt":
            metadata["cmt_allocation"] = {
                "mode": cmt_allocation_mode,
                "kl_budget": float(config["selector"].get("cmt_allocation_kl", 0.5)),
                "weight_min": cmt_weight_min,
                "weight_max": cmt_weight_max,
                "final_kl_budget": cmt_final_allocation_kl,
                "normalization_scope": "global_valid_tokens_within_each_ppo_group",
            }
            metadata["cmt_correction"] = {
                "mode": cmt_correction_mode,
                "quantile": cmt_correction_quantile,
                "normalization_scope": "global_valid_tokens_within_full_rollout",
                "raw_aliases": {
                    "sequential_gain": "sequential_gain_raw",
                    "learning_value": "legacy/raw score before correction",
                    "s_CMT": "actual allocation score",
                },
            }
            metadata["cmt_token_audit"] = {
                "enabled": bool(
                    config.get("logging", {}).get("cmt_token_audit_enabled", False)
                ),
                "interval": int(
                    config.get("logging", {}).get("cmt_token_audit_interval", 150)
                ),
                "top_k": int(
                    config.get("logging", {}).get("cmt_token_audit_top_k", 50)
                ),
                "context_radius": int(
                    config.get("logging", {}).get("cmt_token_context_radius", 32)
                ),
                "gain_heatmap_enabled": bool(
                    config.get("logging", {}).get("cmt_gain_heatmap_enabled", False)
                ),
                "selection_scope": "global_valid_tokens_across_all_ranks",
            }
        metadata["opd_upstream"] = {
            "repository": "https://github.com/thunlp/OPD",
            "commit": UPSTREAM_OPD_COMMIT,
            "adv_estimator": advantage_estimator,
            "top_k_strategy": top_k_strategy,
            "top_k": configured_top_k,
            "loss_support_definition": "student_topk",
            "reward_weight_mode": reward_weight_mode,
            "loss_agg_mode": loss_aggregation,
        }
        metadata["resume"] = (
            {
                "checkpoint": str(resume_state.checkpoint),
                "optimizer_path": str(resume_state.optimizer_path),
                "step": resume_state.step,
                "history": resume_history,
                "config_validation": resume_config_validation,
                "source_world_size": "unknown_for_legacy_checkpoint",
            }
            if resume_state is not None
            else None
        )
        metadata_filename = (
            "run_metadata.json"
            if resume_state is None
            else f"run_metadata.resume-step-{resume_step:06d}.json"
        )
        save_metadata(metadata, output_dir, filename=metadata_filename)
    setup_progress.update(1)
    setup_progress.close()
    if distributed.is_main:
        rendered_train_prompt = render_record_prompt(
            records[0], tokenizer, config["data"]
        )
        first_benchmark = configured_benchmark_names(config)[0]
        evaluation_records, _ = load_benchmark(
            first_benchmark,
            config["evaluation"]["benchmarks"][first_benchmark],
        )
        if not evaluation_records:
            raise ValueError(
                f"Configured evaluation benchmark {first_benchmark} is empty"
            )
        rendered_eval_prompt = render_evaluation_prompt(
            tokenizer, evaluation_records[0], config
        )
        tqdm.write(f"Fully rendered TRAIN prompt:\n{rendered_train_prompt}")
        tqdm.write(
            f"Fully rendered EVAL prompt ({first_benchmark}):\n{rendered_eval_prompt}"
        )
    selector_cfg = config["selector"]
    top_k = configured_top_k
    opd_selector = OPDSelector()
    ta_selector = TASelector(
        top_k,
        float(selector_cfg.get("q_low", 0.05)),
        float(selector_cfg.get("q_high", 0.95)),
        float(selector_cfg.get("eps", 1e-8)),
    )
    rac_selector = RACSelector(
        gamma=float(selector_cfg.get("rac_gamma", 0.995)),
        w_min=float(selector_cfg.get("rac_w_min", 0.10)),
        beta=float(selector_cfg.get("rac_beta", 2.0)),
        q_low=float(selector_cfg.get("q_low", 0.05)),
        q_high=float(selector_cfg.get("q_high", 0.95)),
        eps=float(selector_cfg.get("eps", 1e-8)),
        scan_backend=str(selector_cfg.get("rac_scan_backend", "parallel")),
    )
    pgt_selector = PGTSelector()
    cmt_selector = CMTSelector(
        gamma=float(selector_cfg.get("cmt_gamma", 1.0)),
        successor_lambda=float(selector_cfg.get("cmt_successor_lambda", 1.0)),
        ablation_arm=str(selector_cfg.get("cmt_ablation_arm", "canonical")),
    )
    batch_size = global_prompt_batch_size
    if batch_size <= 0 or num_responses <= 0:
        raise ValueError("Prompt batch size and rollout.num_responses must be positive")
    rollout_batches_per_epoch = math.ceil(len(records) / batch_size)
    optimizer_steps_per_epoch = _optimizer_steps_per_epoch(
        len(records), batch_size, num_responses, ppo_mini_batch_size
    )
    configured_max_steps = training.get("max_steps")
    max_steps = (
        int(configured_max_steps)
        if configured_max_steps is not None
        else int(training.get("epochs", 1)) * optimizer_steps_per_epoch
    )
    if resume_step >= max_steps:
        raise ValueError(
            f"Checkpoint is already at step {resume_step}, but configured total "
            f"max_steps is {max_steps}. Set MAX_STEPS above {resume_step} or "
            "increase EPOCHS. MAX_STEPS is the total target, not extra steps."
        )
    rho = float(config["token_budget"]["rho"])
    token_logger = SelectedTokenLogger(
        output_dir,
        tokenizer,
        method,
        chunk_steps=int(config.get("logging", {}).get("selector_chunk_steps", 50)),
        enabled=method in {"ta", "pgt"}
        and bool(config.get("logging", {}).get("selected_tokens_enabled", True)),
        rank=distributed.rank,
        world_size=distributed.world_size,
    )
    score_stats_logger = TokenScoreStatsLogger(
        output_dir,
        method,
        interval=int(config.get("logging", {}).get("token_score_interval", 50)),
        bins=int(config.get("logging", {}).get("token_score_histogram_bins", 64)),
        raw_sample_size=int(
            config.get("logging", {}).get("token_score_raw_sample_size", 2048)
        ),
        enabled=distributed.is_main
        and bool(config.get("logging", {}).get("token_score_stats_enabled", True)),
    )
    logging_cfg = dict(config.get("logging", {}))
    cmt_audit_logger = CMTTokenAuditLogger(
        output_dir,
        tokenizer,
        enabled=method == "cmt"
        and bool(logging_cfg.get("cmt_token_audit_enabled", False)),
        interval=int(logging_cfg.get("cmt_token_audit_interval", 150)),
        top_k=int(logging_cfg.get("cmt_token_audit_top_k", 50)),
        context_radius=int(logging_cfg.get("cmt_token_context_radius", 32)),
        heatmap_enabled=bool(logging_cfg.get("cmt_gain_heatmap_enabled", False)),
        rank=distributed.rank,
        world_size=distributed.world_size,
    )
    tensorboard_logger = TensorBoardLogger(
        output_dir,
        dict(config.get("logging", {}).get("tensorboard", {})),
        enabled=distributed.is_main,
        resume_step=resume_step,
    )
    training_eval_settings = config.get("training_evaluation", {})
    evaluation_steps = training_evaluation_steps(max_steps, training_eval_settings)
    if evaluation_steps and distributed.is_main:
        tqdm.write(
            f"Periodic evaluation ({training_eval_settings.get('backend', 'vllm')}): "
            + ", ".join(map(str, evaluation_steps))
        )
    if resume_state is not None and distributed.is_main:
        tqdm.write(
            f"Resuming {METHOD_DISPLAY_NAMES[method]} from optimizer step {resume_step}: "
            f"{resume_state.checkpoint}"
        )
        if resume_history is not None and resume_history["rewound"]:
            removed_row_count = sum(resume_history["removed_rows"].values())
            removed_row_count += int(resume_history["selector_rows_removed"])
            tqdm.write(
                f"Rewound existing outputs to step {resume_step}: removed "
                f"{removed_row_count} later log rows and "
                f"{len(resume_history['removed_paths'])} stale paths."
            )
    initial_evaluation = None
    if resume_step == 0 and should_run_training_evaluation(
        0, max_steps, training_eval_settings
    ):
        if distributed.world_size == 1:
            distributed.barrier()
            tqdm.write("Evaluating the untouched base student at optimizer step 0...")
            initial_evaluation = _run_training_evaluation(
                training_student,
                tokenizer,
                method,
                0,
                max_steps,
                config,
                output_dir,
                resolved_config_path,
            )
            distributed.barrier()
        else:
            if distributed.is_main:
                tqdm.write(
                    "Evaluating the untouched base student at optimizer step 0..."
                )
            initial_evaluation = _run_training_evaluation(
                training_student,
                tokenizer,
                method,
                0,
                max_steps,
                config,
                output_dir,
                resolved_config_path,
                distributed=distributed,
            )
            # The filesystem coordinator only returns after all ranks have
            # finished and rank 0 has merged the artifacts. This is a short
            # post-evaluation collective, never a long wait during generation.
            distributed.barrier()
            if not distributed.is_main:
                initial_evaluation = None
    final_metrics: dict[str, Any] = {}
    progress = tqdm(
        total=max_steps,
        desc=f"{METHOD_DISPLAY_NAMES[method]} B200",
        unit="step",
        dynamic_ncols=True,
        leave=True,
        disable=not distributed.is_main,
        mininterval=0.5,
        initial=resume_step,
    )
    optimizer_step = resume_step
    rollout_index, ppo_minibatch_offset = _rollout_position_after_optimizer_steps(
        optimizer_step,
        len(records),
        batch_size,
        num_responses,
        ppo_mini_batch_size,
    )
    while optimizer_step < max_steps:
        step_started = time.perf_counter()
        rollout_first_optimizer_step = optimizer_step + 1
        if distributed.is_main:
            progress.set_postfix_str(f"stage=rollout-{rollout_backend}", refresh=True)
        torch.cuda.reset_peak_memory_stats(device)
        global_indices = epoch_batch_indices(
            len(records), batch_size, rollout_index, seed
        )
        rollout_ppo_minibatches = _ppo_minibatch_count(
            len(global_indices) * num_responses, ppo_mini_batch_size
        )
        optimizer_steps_this_rollout = min(
            rollout_ppo_minibatches - ppo_minibatch_offset,
            max_steps - optimizer_step,
        )
        rollout_last_optimizer_step = optimizer_step + optimizer_steps_this_rollout
        local_start, _ = contiguous_partition(
            len(global_indices), distributed.rank, distributed.world_size
        )
        prompt_indices, active_prompts = padded_local_indices(
            global_indices,
            distributed.rank,
            distributed.world_size,
        )
        prompt_records = [records[index] for index in prompt_indices]
        encoded, _ = tokenize_prompts(prompt_records, tokenizer, config["data"], device)
        encoded, indices, response_indices = expand_prompt_batch(
            encoded, prompt_indices, num_responses
        )
        active_trajectories = torch.tensor(
            [active for active in active_prompts for _ in range(num_responses)],
            dtype=torch.bool,
            device=device,
        )
        batch_records = [records[index] for index in indices]
        rollout_function = (
            rollout_engine.generate
            if rollout_engine is not None
            else generate_on_policy
        )
        rollout, rollout_time = _timed(
            device,
            rollout_function,
            training_student,
            encoded["input_ids"],
            encoded["attention_mask"],
            max_new_tokens=int(config["rollout"].get("max_new_tokens", 256)),
            temperature=float(config["rollout"].get("temperature", 1.0)),
            top_p=float(config["rollout"].get("top_p", 1.0)),
            eos_token_ids=tokenizer.eos_token_id,
            pad_token_id=tokenizer.pad_token_id,
            seed=int(config["rollout"].get("seed", seed)),
            # Repeated prompts are separate requests with globally unique,
            # deterministic seeds, so all n trajectories are independent.
            sample_seed_offset=(
                rollout_index * batch_size * num_responses + local_start * num_responses
            ),
        )
        rollout_backend_metrics = (
            dict(rollout_engine.last_metrics) if rollout_engine is not None else {}
        )
        for field in (
            "input_ids",
            "attention_mask",
            "response_ids",
            "valid_mask",
            "rollout_log_probs",
        ):
            setattr(rollout, field, getattr(rollout, field).clone())
        original_rollout = rollout.input_ids.clone()
        objective_valid = rollout.valid_mask & active_trajectories.unsqueeze(1)
        rollout_hash = _rollout_hash(rollout.response_ids, objective_valid, distributed)
        use_joint_scoring = method in {"pgt", "cmt"} or (
            method in {"ta", "rac"}
            and bool(selector_cfg.get("joint_cross_scoring", True))
        )
        joint_scoring_time = 0.0
        if use_joint_scoring:
            if distributed.is_main:
                progress.set_postfix_str(
                    "stage=score-student-teacher-joint", refresh=True
                )
            joint_scores, joint_scoring_time = _timed(
                device,
                score_student_teacher_rollout,
                training_student,
                scoring_teacher,
                rollout,
                score_chunk_steps=int(selector_cfg.get("score_chunk_steps", 128)),
                top_k=top_k,
                student_temperature=float(config["rollout"].get("temperature", 1.0)),
                teacher_temperature=float(opd_config.get("teacher_temperature", 1.0)),
                micro_batch_size=int(selector_cfg.get("score_micro_batch_size", 1)),
                trim_padding=bool(selector_cfg.get("trim_padding", True)),
                length_bucketed=bool(selector_cfg.get("length_bucketed_scoring", True)),
                compute_full_vocab_metrics=bool(
                    method == "cmt"
                    and selector_cfg.get("cmt_full_vocab_diagnostics", False)
                ),
            )
            student_scores, teacher_scores = joint_scores
            student_base_time = teacher_base_time = 0.0
        else:
            if distributed.is_main:
                progress.set_postfix_str("stage=score-student", refresh=True)
            student_scores, student_base_time = _timed(
                device,
                score_original_rollout,
                training_student,
                rollout,
                False,
                int(selector_cfg.get("score_chunk_steps", 128)),
                retain_response_logits=False,
                top_k=top_k,
                temperature=float(config["rollout"].get("temperature", 1.0)),
                micro_batch_size=int(selector_cfg.get("score_micro_batch_size", 1)),
                trim_padding=bool(selector_cfg.get("trim_padding", True)),
                length_bucketed=bool(selector_cfg.get("length_bucketed_scoring", True)),
            )
        if student_scores.top_k_ids is None or student_scores.top_k_log_probs is None:
            raise AssertionError(
                "Student scoring did not produce the common Top-K support"
            )
        if not use_joint_scoring:
            if distributed.is_main:
                progress.set_postfix_str("stage=score-teacher", refresh=True)
            teacher_scores, teacher_base_time = _timed(
                device,
                score_original_rollout,
                scoring_teacher,
                rollout,
                False,
                int(selector_cfg.get("score_chunk_steps", 128)),
                retain_response_logits=False,
                top_k=top_k,
                candidate_ids=student_scores.top_k_ids,
                temperature=float(opd_config.get("teacher_temperature", 1.0)),
                micro_batch_size=int(selector_cfg.get("score_micro_batch_size", 1)),
                trim_padding=bool(selector_cfg.get("trim_padding", True)),
                length_bucketed=bool(selector_cfg.get("length_bucketed_scoring", True)),
            )
        if (
            teacher_scores.candidate_log_probs is None
            or teacher_scores.top_k_ids is None
            or teacher_scores.top_k_log_probs is None
        ):
            raise AssertionError("Teacher scoring did not score the student Top-K IDs")
        valid = objective_valid
        finite_or_raise(
            "student sampled log-probs", student_scores.sampled_log_probs[valid]
        )
        finite_or_raise(
            "teacher sampled log-probs", teacher_scores.sampled_log_probs[valid]
        )
        pgt_raw: PGTOutput | None = None
        pgt_score_time = 0.0
        if method in {"pgt", "cmt"}:
            if student_scores.candidate_log_probs is None:
                raise AssertionError(
                    "Joint scoring did not produce student probabilities on teacher Top-K"
                )
            pgt_raw, pgt_score_time = _timed(
                device,
                pgt_selector.compute_scores_from_topk,
                student_scores.top_k_ids,
                teacher_scores.top_k_ids,
                student_scores.top_k_log_probs,
                teacher_scores.candidate_log_probs,
                teacher_scores.top_k_log_probs,
                student_scores.candidate_log_probs,
                valid,
                token_chunk_size=int(selector_cfg.get("pgt_vocab_chunk_tokens", 2048)),
                gain_support="student_topk" if method == "cmt" else "union",
            )
        cmt_raw: PGTOutput | None = None
        cmt_score_time = 0.0
        if method == "cmt":
            if pgt_raw is None:
                raise AssertionError("CMT requires the shared PGT support")
            cmt_raw, cmt_score_time = _timed(
                device,
                cmt_selector.compute_scores,
                pgt_raw,
                rollout.response_ids,
                valid,
            )
            if student_scores.full_log_ratio_mean is not None:
                for field in (
                    "full_log_ratio_mean",
                    "full_log_ratio_variance",
                    "full_common_mass",
                ):
                    value = getattr(student_scores, field)
                    if value is not None:
                        finite_or_raise(f"CMT diagnostic {field}", value[valid])
                        cmt_raw.diagnostics[field] = value.detach().float()
        iw_weights: torch.Tensor | None = None
        iw_weight_stats: dict[str, float] | None = None
        if method == "iw":
            # Official IW-OPD uses the sampled response action (not a
            # candidate-wise Top-K reward) and applies a stop-gradient prefix
            # remaining-discrepancy multiplier to that OPD advantage.
            opd_reference, iw_weights = build_iw_opd_reference(
                rollout.response_ids,
                student_scores.sampled_log_probs,
                teacher_scores.sampled_log_probs,
                valid,
                weight_max=float(config.get("iw_opd", {}).get("weight_max", 1.5)),
                use_abs=bool(config.get("iw_opd", {}).get("use_abs", True)),
                eps=float(config.get("iw_opd", {}).get("eps", 1.0e-8)),
            )
            iw_weight_stats = _global_tensor_stats(iw_weights[valid], distributed)
        elif method in {"opd", "ta", "cmt"}:
            opd_reference = build_student_topk_opd_reference(
                student_scores.top_k_ids,
                student_scores.top_k_log_probs,
                teacher_scores.candidate_log_probs,
                valid,
                top_k=top_k,
            )
            if not torch.equal(opd_reference.candidate_ids, student_scores.top_k_ids):
                raise AssertionError(
                    f"{method.upper()} policy-loss support differs from configured "
                    f"Student Top-{top_k}"
                )
        else:
            opd_reference = build_topk_opd_reference(
                student_scores.top_k_ids,
                student_scores.top_k_log_probs,
                teacher_scores.candidate_log_probs,
                valid,
            )
        finite_or_raise("Top-K OPD advantages", opd_reference.advantages[valid])
        advantage_stats = _global_tensor_stats(
            opd_reference.advantages[valid], distributed
        )
        advantage_abs_stats = _global_tensor_stats(
            opd_reference.advantages[valid].abs(), distributed
        )
        opd_advantage_abs_mean = advantage_abs_stats["mean"]
        local_logprob_gap = (
            teacher_scores.sampled_log_probs[valid]
            - student_scores.sampled_log_probs[valid]
        )
        global_logprob_gap_count = distributed.sum_int(local_logprob_gap.numel())
        opd_teacher_student_logprob_gap = distributed.sum_float(
            float(local_logprob_gap.sum().item())
        ) / max(global_logprob_gap_count, 1)
        overlap_values = topk_overlap_fraction(
            student_scores.top_k_ids, teacher_scores.top_k_ids, valid
        )
        global_overlap_count = distributed.sum_int(overlap_values.numel())
        student_teacher_topk_overlap = distributed.sum_float(
            float(overlap_values.sum().item())
        ) / max(global_overlap_count, 1)
        local_divergence = -opd_reference.advantages.sum(dim=-1)[valid]
        divergence_proxy_stats = _global_tensor_stats(local_divergence, distributed)
        student_teacher_topk_divergence_proxy = divergence_proxy_stats["mean"]
        student_entropy_stats = _global_tensor_stats(
            student_scores.entropies[valid], distributed
        )
        teacher_entropy_stats = _global_tensor_stats(
            teacher_scores.entropies[valid], distributed
        )
        entropy_gap_stats = _global_tensor_stats(
            (student_scores.entropies[valid] - teacher_scores.entropies[valid]).abs(),
            distributed,
        )
        student_topk_mass_stats = _global_tensor_stats(
            student_scores.top_k_log_probs[valid].float().exp().sum(dim=-1),
            distributed,
        )
        teacher_topk_mass_stats = _global_tensor_stats(
            teacher_scores.top_k_log_probs[valid].float().exp().sum(dim=-1),
            distributed,
        )

        vllm_logprob_sanity: dict[str, Any] = {"enabled": False}
        sanity = dict(config["rollout"].get("vllm", {}).get("logprob_sanity", {}))
        if rollout_backend == "vllm" and bool(sanity.get("enabled", False)):
            comparable = valid & torch.isfinite(rollout.rollout_log_probs)
            differences = (
                rollout.rollout_log_probs[comparable]
                - student_scores.sampled_log_probs[comparable]
            ).abs()[: max(1, int(sanity.get("max_tokens_per_rank", 32)))]
            compared = distributed.sum_int(differences.numel())
            if compared == 0:
                raise RuntimeError(
                    "vLLM log-prob sanity was enabled, but the server returned no "
                    "token log-probabilities"
                )
            mean_abs = distributed.sum_float(float(differences.sum().item())) / max(
                compared, 1
            )
            local_max_abs = (
                float(differences.max().item()) if differences.numel() else 0.0
            )
            max_abs = distributed.max_float(local_max_abs)
            tolerance = float(sanity.get("tolerance", 0.05))
            vllm_logprob_sanity = {
                "enabled": True,
                "compared_tokens": compared,
                "mean_abs_error": mean_abs,
                "max_abs_error": max_abs,
                "tolerance": tolerance,
                "passed": max_abs <= tolerance,
            }
            if not vllm_logprob_sanity["passed"] and bool(
                sanity.get("fail_on_mismatch", False)
            ):
                raise RuntimeError(
                    "vLLM/HF student log-prob sanity failed after weight sync: "
                    f"max_abs_error={max_abs:.6f} > tolerance={tolerance:.6f}"
                )
        cross_diagnostics = {}
        ta_raw = ta_output = None
        global_ta_diagnostics: dict[str, torch.Tensor] = {}
        global_pgt_diagnostics: dict[str, torch.Tensor] = {}
        global_cmt_diagnostics: dict[str, torch.Tensor] = {}
        cmt_correction_metrics: dict[str, float] = {}
        student_cross_score_time = 0.0
        if method == "iw":
            if distributed.is_main:
                progress.set_postfix_str(
                    "stage=selector-IW-OPD-prefix-remaining-mass", refresh=True
                )
            # IW-OPD supervises every valid sampled response token.  The
            # importance weight lives in the frozen PPO advantage above, not
            # in the token allocator; this preserves the official token-mean
            # objective and avoids double-weighting the loss denominator.
            iw_position_weights = valid.float()
            primary = SelectorOutput(
                iw_position_weights,
                {"w": iw_position_weights, "iw_weight": iw_weights},
            )
            iw_globalized, iw_gather_time = _timed(
                device,
                _globalize_opd_output,
                primary,
                valid,
                distributed,
            )
            primary, global_primary_diagnostics, primary_start, primary_end = (
                iw_globalized
            )
            if iw_weights is not None:
                global_iw_weights, iw_start, iw_end, _iw_lengths = (
                    distributed.all_gather_variable_1d(iw_weights[valid])
                )
                if (iw_start, iw_end) != (primary_start, primary_end):
                    raise AssertionError("IW distributed token layouts differ")
                global_primary_diagnostics["iw_weight"] = global_iw_weights
            ta_time = bellman_scan_time = 0.0
            selector_time = iw_gather_time
        elif method == "opd":
            if distributed.is_main:
                progress.set_postfix_str("stage=selector-OPD-uniform", refresh=True)
            opd_raw, opd_selector_time = _timed(
                device,
                opd_selector.compute_scores,
                valid,
            )
            opd_globalized, opd_gather_time = _timed(
                device,
                _globalize_opd_output,
                opd_raw,
                valid,
                distributed,
            )
            primary, global_primary_diagnostics, primary_start, primary_end = (
                opd_globalized
            )
            del opd_raw
            ta_time = bellman_scan_time = 0.0
            selector_time = opd_selector_time + opd_gather_time
        elif method == "pgt":
            if pgt_raw is None:
                raise AssertionError("PGT selector output was not computed")
            if distributed.is_main:
                progress.set_postfix_str(
                    "stage=selector-PGT-projected-gradient", refresh=True
                )
            pgt_globalized, pgt_gather_time = _timed(
                device,
                _globalize_pgt_output,
                pgt_raw,
                valid,
                distributed,
            )
            primary, global_pgt_diagnostics, primary_start, primary_end = pgt_globalized
            ta_time = pgt_score_time
            bellman_scan_time = 0.0
            selector_time = pgt_score_time + pgt_gather_time
            global_primary_diagnostics = global_pgt_diagnostics
        elif method == "cmt":
            if cmt_raw is None:
                raise AssertionError("CMT selector output was not computed")
            if distributed.is_main:
                progress.set_postfix_str(
                    "stage=selector-CMT-common-mass-successor", refresh=True
                )
            cmt_globalized, cmt_gather_time = _timed(
                device,
                _globalize_cmt_output,
                cmt_raw,
                valid,
                distributed,
            )
            primary, global_cmt_diagnostics, primary_start, primary_end = cmt_globalized
            (
                primary,
                global_cmt_diagnostics,
                cmt_correction_metrics,
            ) = _apply_global_cmt_correction(
                primary,
                global_cmt_diagnostics,
                valid,
                primary_start,
                primary_end,
                mode=cmt_correction_mode,
                quantile=cmt_correction_quantile,
            )
            ta_time = pgt_score_time
            bellman_scan_time = cmt_score_time
            selector_time = pgt_score_time + cmt_score_time + cmt_gather_time
            global_primary_diagnostics = global_cmt_diagnostics
        else:
            if use_joint_scoring:
                student_on_teacher = student_scores
            else:
                student_on_teacher, student_cross_score_time = _timed(
                    device,
                    score_original_rollout,
                    training_student,
                    rollout,
                    False,
                    int(selector_cfg.get("score_chunk_steps", 128)),
                    retain_response_logits=False,
                    candidate_ids=teacher_scores.top_k_ids,
                    temperature=float(config["rollout"].get("temperature", 1.0)),
                    micro_batch_size=int(selector_cfg.get("score_micro_batch_size", 1)),
                    trim_padding=bool(selector_cfg.get("trim_padding", True)),
                    length_bucketed=bool(
                        selector_cfg.get("length_bucketed_scoring", True)
                    ),
                )
            if student_on_teacher.candidate_log_probs is None:
                raise AssertionError("Student did not score the teacher Top-K IDs")
            ta_raw, ta_raw_time = _timed(
                device,
                ta_selector.compute_scores_from_topk,
                student_scores.top_k_ids,
                teacher_scores.top_k_ids,
                student_scores.top_k_log_probs,
                teacher_scores.candidate_log_probs,
                teacher_scores.top_k_log_probs,
                student_on_teacher.candidate_log_probs,
                valid,
                normalize=False,
                token_chunk_size=int(selector_cfg.get("ta_vocab_chunk_tokens", 2048)),
            )
            del student_on_teacher
            ta_globalized, ta_normalization_time = _timed(
                device,
                _globalize_ta_output,
                ta_raw,
                valid,
                ta_selector,
                distributed,
            )
            ta_output, global_ta_diagnostics, ta_start, ta_end = ta_globalized
            ta_time = student_cross_score_time + ta_raw_time + ta_normalization_time
            if method == "rac":
                if distributed.is_main:
                    progress.set_postfix_str("stage=selector-Bellman-RAC", refresh=True)
                rac_raw, bellman_scan_time = _timed(
                    device,
                    rac_selector.compute_scores,
                    ta_output.scores,
                    student_scores.sampled_log_probs,
                    teacher_scores.sampled_log_probs,
                    valid,
                    normalize=False,
                )
                rac_globalized, rac_normalization_time = _timed(
                    device,
                    _globalize_rac_output,
                    rac_raw,
                    valid,
                    rac_selector,
                    distributed,
                )
                primary, global_primary_diagnostics, primary_start, primary_end = (
                    rac_globalized
                )
                del rac_raw
                if (primary_start, primary_end) != (ta_start, ta_end):
                    raise AssertionError("TA/RAC distributed token layouts differ")
                cross_diagnostics.update(
                    correlations(
                        global_ta_diagnostics["s_TA"],
                        global_primary_diagnostics,
                        torch.ones_like(
                            global_ta_diagnostics["s_TA"], dtype=torch.bool
                        ),
                    )
                )
                selector_time = bellman_scan_time + rac_normalization_time
            else:
                if distributed.is_main:
                    progress.set_postfix_str("stage=selector-TA", refresh=True)
                primary, selector_time, bellman_scan_time = (
                    ta_output,
                    ta_time,
                    0.0,
                )
                global_primary_diagnostics = global_ta_diagnostics
                primary_start, primary_end = ta_start, ta_end
        finite_or_raise(f"{method} selector", primary.scores[valid])
        score_key = (
            "s_TA"
            if method == "ta"
            else "s_PGT"
            if method == "pgt"
            else "s_CMT"
            if method == "cmt"
            else "w"
        )
        if method in {"ta", "pgt"}:
            selected, global_selected = _local_mask_from_global_budget(
                global_primary_diagnostics[score_key],
                valid,
                primary_start,
                primary_end,
                rho,
            )
            expected = math.ceil(rho * global_primary_diagnostics[score_key].numel())
            token_allocation = selected
        else:
            selected = valid.clone()
            global_selected = torch.ones_like(
                global_primary_diagnostics[score_key], dtype=torch.bool
            )
            expected = global_primary_diagnostics[score_key].numel()
            # CMT's actual weights are solved inside each PPO optimizer group.
            # This placeholder is never read by _opd_train_step when
            # gibbs_scores is supplied below.
            token_allocation = selected if method in {"opd", "cmt"} else primary.scores
        # RAC selector computations run under inference_mode.  Materialize a
        # normal frozen tensor before it participates in a differentiable
        # weighted loss (the same guard used by TopKOPDReference).
        with torch.inference_mode(False):
            token_allocation = token_allocation.detach().clone()
        if distributed.sum_int(int(selected.sum().item())) != expected:
            raise AssertionError(f"{method} supervised-token count is incorrect")
        if not torch.equal(original_rollout, rollout.input_ids):
            raise AssertionError("Selector changed the original rollout")
        token_score_stats_path = None
        if method != "cmt" and distributed.is_main:
            token_score_stats_path = score_stats_logger.write(
                rollout_last_optimizer_step, max_steps, global_primary_diagnostics
            )
        sample_ids = [
            f"{stable_sample_id(record, index)}::response-{response_index}"
            for record, index, response_index in zip(
                batch_records, indices, response_indices
            )
        ]
        logged_selected = (
            token_logger.write(
                step=rollout_last_optimizer_step,
                dataset_indices=indices,
                sample_ids=sample_ids,
                response_ids=rollout.response_ids,
                selected_mask=selected,
                diagnostics=primary.diagnostics,
                batch_index_offset=local_start * num_responses,
            )
            if method in {"ta", "pgt"}
            else 0
        )
        global_logged_selected = distributed.sum_int(logged_selected)
        if (
            bool(config.get("logging", {}).get("selected_tokens_enabled", True))
            and method in {"ta", "pgt"}
            and global_logged_selected != expected
        ):
            raise AssertionError(
                f"Detailed selector logs wrote {global_logged_selected}, "
                f"expected {expected}"
            )

        del student_scores, teacher_scores
        # Let PyTorch reuse the released scoring-logit blocks for backward.
        # Emptying the CUDA allocator every step is materially slower on B200.
        if bool(training.get("empty_cuda_cache_each_step", False)):
            torch.cuda.empty_cache()
        if distributed.is_main:
            progress.set_postfix_str("stage=train", refresh=True)
        checkpoints_by_step: dict[int, Path] = {}
        evaluation_sources: dict[int, tuple[Path, bool]] = {}
        save_checkpoints = bool(training.get("save_checkpoints", True))
        save_interval = int(training.get("save_interval", 100))

        def after_optimizer_step(current_step: int, _metrics: dict[str, float]) -> None:
            should_evaluate = should_run_training_evaluation(
                current_step, max_steps, training_eval_settings
            )
            should_save = save_checkpoints and (
                current_step == max_steps
                or (save_interval > 0 and current_step % save_interval == 0)
            )
            checkpoint_path = None
            if should_save:
                if distributed.is_main:
                    progress.set_postfix_str("stage=checkpoint", refresh=True)
                checkpoint_path = _save_checkpoint(
                    training_student,
                    tokenizer,
                    optimizer,
                    output_dir,
                    current_step,
                    current_step == max_steps,
                    bool(training.get("save_optimizer", True)),
                    distributed,
                )
                checkpoints_by_step[current_step] = checkpoint_path
            if should_evaluate:
                evaluation_path = checkpoint_path
                temporary = False
                if evaluation_path is None:
                    evaluation_path = (
                        output_dir
                        / ".evaluation_snapshots"
                        / f"step-{current_step:06d}"
                    )
                    if distributed.is_main and evaluation_path.exists():
                        shutil.rmtree(evaluation_path)
                    distributed.barrier()
                    _save_inference_snapshot(
                        training_student,
                        tokenizer,
                        evaluation_path,
                        distributed,
                    )
                    temporary = True
                evaluation_sources[current_step] = (evaluation_path, temporary)
            if distributed.is_main:
                progress.update(1)

        train_metrics = _opd_train_step(
            training_student,
            optimizer,
            rollout,
            token_allocation,
            opd_reference,
            config,
            device,
            distributed,
            objective_valid_mask=objective_valid,
            trajectory_active_mask=active_trajectories,
            trajectory_group_ids=(response_indices if method == "cmt" else None),
            gibbs_scores=(primary.scores if method == "cmt" else None),
            gibbs_epsilon=(
                float(selector_cfg.get("cmt_allocation_kl", 0.5))
                if method == "cmt"
                else None
            ),
            gibbs_mode=cmt_allocation_mode,
            gibbs_weight_min=cmt_weight_min,
            gibbs_weight_max=cmt_weight_max,
            gibbs_final_epsilon=cmt_final_allocation_kl,
            rollout_id=rollout_index,
            ppo_minibatch_offset=ppo_minibatch_offset,
            max_optimizer_steps=max_steps - optimizer_step,
            optimizer_step_start=optimizer_step,
            on_optimizer_step=after_optimizer_step,
        )
        if method == "cmt":
            local_cmt_weights = train_metrics.pop("allocated_position_weights")
            local_cmt_raw_weights = train_metrics.pop("allocated_raw_position_weights")
            local_cmt_group_indices = train_metrics.pop("allocated_group_indices")
            local_cmt_optimizer_steps = train_metrics.pop("allocated_optimizer_steps")
            local_cmt_processed = train_metrics.pop("allocated_processed_mask")
            if local_cmt_weights is None:
                raise AssertionError(
                    "CMT training did not return groupwise Gibbs weights"
                )
            if local_cmt_raw_weights is None:
                raise AssertionError("CMT training did not return raw Gibbs weights")
            if any(
                value is None
                for value in (
                    local_cmt_group_indices,
                    local_cmt_optimizer_steps,
                    local_cmt_processed,
                )
            ):
                raise AssertionError(
                    "CMT training did not return allocation scope metadata"
                )
            global_cmt_weights, weight_start, weight_end, _weight_lengths = (
                distributed.all_gather_variable_1d(local_cmt_weights[valid])
            )
            global_cmt_raw_weights, raw_start, raw_end, _raw_lengths = (
                distributed.all_gather_variable_1d(local_cmt_raw_weights[valid])
            )
            global_cmt_group_indices, group_start, group_end, _group_lengths = (
                distributed.all_gather_variable_1d(local_cmt_group_indices[valid])
            )
            global_cmt_optimizer_steps, step_start, step_end, _step_lengths = (
                distributed.all_gather_variable_1d(local_cmt_optimizer_steps[valid])
            )
            global_cmt_processed, processed_start, processed_end, _processed_lengths = (
                distributed.all_gather_variable_1d(local_cmt_processed[valid])
            )
            if (weight_start, weight_end) != (primary_start, primary_end):
                raise AssertionError(
                    "CMT score/weight distributed token layouts differ"
                )
            if (raw_start, raw_end) != (primary_start, primary_end):
                raise AssertionError("CMT raw-weight distributed token layouts differ")
            for metadata_layout in (
                (group_start, group_end),
                (step_start, step_end),
                (processed_start, processed_end),
            ):
                if metadata_layout != (primary_start, primary_end):
                    raise AssertionError("CMT allocation metadata token layouts differ")
            global_cmt_processed = global_cmt_processed.bool()
            global_primary_diagnostics["w_raw"] = global_cmt_raw_weights
            global_primary_diagnostics["w"] = global_cmt_weights
            global_primary_diagnostics["allocation_group_index"] = (
                global_cmt_group_indices
            )
            global_primary_diagnostics["allocation_optimizer_step"] = (
                global_cmt_optimizer_steps
            )
            global_primary_diagnostics["allocation_processed"] = global_cmt_processed
            global_cmt_diagnostics["w_raw"] = global_cmt_raw_weights
            global_cmt_diagnostics["w"] = global_cmt_weights
            global_cmt_diagnostics["allocation_group_index"] = global_cmt_group_indices
            global_cmt_diagnostics["allocation_optimizer_step"] = (
                global_cmt_optimizer_steps
            )
            global_cmt_diagnostics["allocation_processed"] = global_cmt_processed
            processed_raw = global_cmt_raw_weights[global_cmt_processed]
            processed_final = global_cmt_weights[global_cmt_processed]
            if processed_final.numel() == 0:
                raise AssertionError("CMT completed no token allocation")
            cmt_allocation_metrics = cmt_weight_metrics(
                processed_raw,
                processed_final,
                weight_min=cmt_weight_min,
                weight_max=cmt_weight_max,
            )
            if cmt_allocation_mode == "gibbs":
                cmt_allocation_metrics["fraction_at_weight_min"] = 0.0
                cmt_allocation_metrics["fraction_at_weight_max"] = 0.0
            cmt_diagnostics = dict(primary.diagnostics)
            cmt_diagnostics.update(
                w_raw=local_cmt_raw_weights,
                w=local_cmt_weights,
                allocation_group_index=local_cmt_group_indices,
                allocation_optimizer_step=local_cmt_optimizer_steps,
                allocation_processed=local_cmt_processed,
                allocation_mode=cmt_allocation_mode,
                allocation_kl_epsilon=float(selector_cfg.get("cmt_allocation_kl", 0.5)),
                allocation_count=int(train_metrics["gibbs_allocations"]),
            )
            primary = SelectorOutput(local_cmt_weights, cmt_diagnostics)
            token_allocation = local_cmt_weights
            score_key = "w"
            global_selected = global_cmt_processed
            selector_time += float(train_metrics["gibbs_allocation_time"])
            if distributed.is_main:
                processed_stats = {
                    key: (
                        value[global_cmt_processed]
                        if torch.is_tensor(value)
                        and value.shape == global_cmt_processed.shape
                        else value
                    )
                    for key, value in global_primary_diagnostics.items()
                }
                token_score_stats_path = score_stats_logger.write(
                    rollout_last_optimizer_step,
                    max_steps,
                    processed_stats,
                )
            audit_paths: list[str] = []
            motivation_summary_paths: list[str] = []
            allocation_metrics_by_step = {
                int(item["optimizer_step"]): item
                for item in train_metrics["minibatches"]
            }
            for audit_step in cmt_audit_logger.audit_steps(
                rollout_first_optimizer_step,
                rollout_last_optimizer_step,
                max_steps,
            ):
                audit_mask = (
                    global_cmt_processed
                    & global_cmt_optimizer_steps.eq(int(audit_step))
                    & global_cmt_group_indices.ge(0)
                )
                sparse_examples: list[dict[str, Any]] = []
                group_summaries: list[dict[str, Any]] = []
                for group_index_tensor in torch.unique(
                    global_cmt_group_indices[audit_mask]
                ):
                    group_index = int(group_index_tensor.item())
                    group_mask = audit_mask & global_cmt_group_indices.eq(group_index)
                    group_diagnostics = {
                        key: value[group_mask]
                        for key, value in global_primary_diagnostics.items()
                        if torch.is_tensor(value)
                        and value.shape == global_cmt_processed.shape
                    }
                    motivation, group_sparse = cmt_motivation_summary(
                        group_diagnostics,
                        global_cmt_weights[group_mask],
                        torch.arange(
                            global_cmt_processed.numel(),
                            device=global_cmt_processed.device,
                        )[group_mask],
                    )
                    solver_event = allocation_metrics_by_step[int(audit_step)]
                    group_summary = {
                        "allocation_id": solver_event["allocation_id"],
                        "rollout_id": int(solver_event["rollout_id"]),
                        "optimizer_step": int(solver_event["optimizer_step"]),
                        "ppo_group_index": int(solver_event["ppo_group_index"]),
                        "group_valid_token_count": int(
                            solver_event["group_valid_token_count"]
                        ),
                        "response_index_composition": solver_event[
                            "response_index_composition"
                        ],
                        **motivation,
                    }
                    group_summaries.append(group_summary)
                    sparse_examples.extend(group_sparse)
                summary_path = cmt_audit_logger.write_motivation_summary(
                    step=audit_step,
                    rollout_id=rollout_index,
                    correction=cmt_correction_metrics,
                    allocation_groups=group_summaries,
                )
                if summary_path is not None:
                    motivation_summary_paths.append(str(summary_path))
                audit_path = cmt_audit_logger.write(
                    step=audit_step,
                    rollout_id=rollout_index,
                    sample_ids=sample_ids,
                    dataset_indices=indices,
                    response_indices=response_indices,
                    response_ids=rollout.response_ids,
                    valid_mask=valid,
                    local_diagnostics=primary.diagnostics,
                    global_diagnostics=global_primary_diagnostics,
                    global_start=primary_start,
                    batch_index_offset=local_start * num_responses,
                    max_response_length=int(config["rollout"]["max_new_tokens"]),
                    extra_selections=sparse_examples,
                )
                if audit_path is not None:
                    audit_paths.append(str(audit_path))
        else:
            cmt_allocation_metrics = {}
            audit_paths = []
            motivation_summary_paths = []
        optimizer_steps_completed = int(train_metrics["optimizer_steps"])
        optimizer_step += optimizer_steps_completed
        step = optimizer_step
        checkpoint = checkpoints_by_step.get(step)
        cuda_sync(device)
        local_wall_time = time.perf_counter() - step_started
        local_valid_tokens = int(valid.sum().item())
        response_lengths = valid.sum(dim=-1)
        active_responses = response_lengths.gt(0)
        local_response_count = int(active_responses.sum().item())
        if local_response_count:
            local_response_min = int(response_lengths[active_responses].min().item())
            local_response_max = int(response_lengths[active_responses].max().item())
        else:
            # An inactive-only rank is possible for a one-prompt dataset tail.
            # Use a neutral max and a high min sentinel for global reduction.
            local_response_min = int(config["rollout"]["max_new_tokens"]) + 1
            local_response_max = 0
        local_clipped_responses = int(
            (
                response_lengths.ge(int(config["rollout"]["max_new_tokens"]))
                & active_responses
            )
            .sum()
            .item()
        )
        eos_token_ids = tokenizer.eos_token_id
        eos_token_ids = (
            [eos_token_ids] if isinstance(eos_token_ids, int) else eos_token_ids
        )
        response_has_eos = torch.zeros_like(active_responses)
        for eos_token_id in eos_token_ids:
            response_has_eos |= (
                rollout.response_ids.eq(int(eos_token_id)) & valid
            ).any(dim=-1)
        local_eos_responses = int((response_has_eos & active_responses).sum().item())
        local_peak_allocated = torch.cuda.max_memory_allocated(device)
        local_peak_reserved = torch.cuda.max_memory_reserved(device)
        wall_time = distributed.max_float(local_wall_time)
        valid_tokens = distributed.sum_int(local_valid_tokens)
        trajectory_count = distributed.sum_int(local_response_count)
        response_min = -distributed.max_int(-local_response_min)
        response_max = distributed.max_int(local_response_max)
        clipped_responses = distributed.sum_int(local_clipped_responses)
        eos_responses = distributed.sum_int(local_eos_responses)
        global_tail_padding_prompts = distributed.sum_int(
            len(active_prompts) - sum(active_prompts)
        )
        peak_allocated = distributed.max_int(local_peak_allocated)
        peak_reserved = distributed.max_int(local_peak_reserved)
        peak_allocated_total = distributed.sum_int(local_peak_allocated)
        peak_reserved_total = distributed.sum_int(local_peak_reserved)
        aggregated_train_metrics = {
            "loss": train_metrics["loss"],
            "train_loss": train_metrics["loss"],
            "weighted_final_loss": train_metrics["weighted_final_loss"],
            "base_topk_opd_loss": train_metrics["base_topk_opd_loss"],
            "unweighted_opd_loss": train_metrics["unweighted_opd_loss"],
            "gradient_norm": distributed.max_float(train_metrics["gradient_norm"]),
            "grad_norm": distributed.max_float(train_metrics["gradient_norm"]),
            "training_forward_time": distributed.max_float(
                train_metrics["training_forward_time"]
            ),
            "backward_time": distributed.max_float(train_metrics["backward_time"]),
            "optimizer_time": distributed.max_float(train_metrics["optimizer_time"]),
            "global_weight_mass": train_metrics["global_weight_mass"],
            "opd_clip_fraction": train_metrics["clip_fraction"],
            "opd_ratio_mean": train_metrics["ratio_mean"],
            "opd_ratio_min": train_metrics["ratio_min"],
            "opd_ratio_max": train_metrics["ratio_max"],
        }
        final_metrics = {
            "step": step,
            "epoch": rollout_index // rollout_batches_per_epoch,
            "step_in_epoch": rollout_index % rollout_batches_per_epoch,
            "rollout_batch_index": rollout_index,
            "rollout_first_optimizer_step": rollout_first_optimizer_step,
            "rollout_last_optimizer_step": step,
            "method": method,
            "resumed_from": (
                str(resume_state.checkpoint) if resume_state is not None else None
            ),
            "resume_step": resume_step,
            "batch_size": len(global_indices),
            "prompt_batch_size": len(global_indices),
            "global_prompt_batch_size": len(global_indices),
            "local_prompt_batch_size": len(prompt_indices),
            "local_real_prompt_count_rank0": sum(active_prompts),
            "tail_padding_prompt_count": global_tail_padding_prompts,
            "num_responses_per_prompt": num_responses,
            "trajectory_batch_size": len(global_indices) * num_responses,
            "global_trajectory_batch_size": len(global_indices) * num_responses,
            "local_trajectory_batch_size": len(prompt_indices) * num_responses,
            "num_trajectories": trajectory_count,
            "local_batch_size_rank0": (
                len(global_indices) // distributed.world_size
                + int(0 < len(global_indices) % distributed.world_size)
            )
            * num_responses,
            "configured_batch_size": batch_size,
            "ppo_mini_batch_size": ppo_mini_batch_size,
            "local_ppo_mini_batch_size": (
                (ppo_mini_batch_size + distributed.world_size - 1)
                // distributed.world_size
            ),
            "ppo_minibatches_in_rollout": optimizer_steps_completed,
            "trajectories_per_full_rollout": len(global_indices) * num_responses,
            "ppo_groups_per_full_rollout": rollout_ppo_minibatches,
            "gibbs_allocations_in_rollout": int(train_metrics["gibbs_allocations"]),
            "optimizer_steps_in_rollout": optimizer_steps_completed,
            "trajectories_per_gibbs": (
                ppo_mini_batch_size if method == "cmt" else None
            ),
            "cmt_allocation_mode": cmt_allocation_mode if method == "cmt" else None,
            "cmt_weight_min": cmt_weight_min if method == "cmt" else None,
            "cmt_weight_max": cmt_weight_max if method == "cmt" else None,
            "cmt_correction_mode": cmt_correction_mode if method == "cmt" else None,
            "cmt_correction_quantile": (
                cmt_correction_quantile if method == "cmt" else None
            ),
            "cmt_final_allocation_kl": (
                cmt_final_allocation_kl if method == "cmt" else None
            ),
            "micro_batch_size_per_gpu": micro_batch_size_per_gpu,
            "distributed_world_size": distributed.world_size,
            "distributed_strategy": strategy,
            "global_batch_preserved": True,
            "global_ta_normalization": method in {"ta", "rac"},
            "global_token_budget": method in {"ta", "pgt"},
            "uniform_full_response_mask": method == "opd",
            "all_response_tokens_supervised": method in {"opd", "rac", "cmt", "iw"},
            "token_allocation_policy": {
                "opd": "uniform_all_valid_response_tokens",
                "ta": "hard_global_top_rho",
                "rac": "bellman_soft_all_valid_response_tokens",
                "pgt": "hard_global_top_rho_projected_gradient_gain",
                "cmt": "kl_constrained_per_ppo_group_coupled_marginal_teachability",
                "iw": "official_prefix_remaining_discrepancy_advantage_weight",
            }[method],
            "objective_normalization": "global_weighted_token_mean",
            "opd_upstream_commit": UPSTREAM_OPD_COMMIT,
            "support_definition": (
                "sampled_response_action" if method == "iw" else "student_topk"
            ),
            "loss_support_definition": (
                "sampled_response_action" if method == "iw" else "student_topk"
            ),
            "selector_support_definition": {
                "opd": "uniform_positions_no_selector_action_support",
                "ta": "literal_union_student_topk_teacher_topk",
                "rac": "literal_union_student_topk_teacher_topk",
                "pgt": "literal_union_student_topk_teacher_topk",
                "cmt": (
                    "g_student_topk__transition_literal_union_"
                    "student_topk_teacher_topk"
                ),
                "iw": "sampled_response_action",
            }[method],
            "opd_candidate_support": (
                "sampled_response_action" if method == "iw" else "student_topk"
            ),
            "opd_support_geometry": (
                "sampled_action_singleton"
                if method == "iw"
                else "global_log_probabilities_on_student_topk_candidates"
            ),
            "opd_top_k": top_k,
            "opd_top_k_strategy": top_k_strategy,
            "opd_reward_weight_mode": reward_weight_mode,
            "opd_adv_estimator": advantage_estimator,
            "opd_loss_agg_mode": loss_aggregation,
            "opd_advantage_abs_mean": opd_advantage_abs_mean,
            "opd_advantage_mean": advantage_stats["mean"],
            "opd_advantage_min": advantage_stats["min"],
            "opd_advantage_max": advantage_stats["max"],
            "opd_teacher_student_logprob_gap": (opd_teacher_student_logprob_gap),
            "iw_weight_mean": (
                iw_weight_stats["mean"] if iw_weight_stats is not None else None
            ),
            "iw_weight_std": (
                iw_weight_stats["std"] if iw_weight_stats is not None else None
            ),
            "iw_weight_min": (
                iw_weight_stats["min"] if iw_weight_stats is not None else None
            ),
            "iw_weight_max": (
                iw_weight_stats["max"] if iw_weight_stats is not None else None
            ),
            "fused_optimizer": fused_optimizer,
            "lr": float(optimizer.param_groups[0]["lr"]),
            **aggregated_train_metrics,
            "rollout_backend": rollout_backend,
            "rollout_time": distributed.max_float(rollout_time),
            "vllm_weight_sync_time": distributed.max_float(
                rollout_backend_metrics.get("weight_sync_time", 0.0)
            ),
            "vllm_full_weight_materialization_time": distributed.max_float(
                rollout_backend_metrics.get("full_weight_materialization_time", 0.0)
            ),
            "vllm_ipc_weight_sync_time": distributed.max_float(
                rollout_backend_metrics.get("ipc_weight_sync_time", 0.0)
            ),
            "vllm_generation_time": distributed.max_float(
                rollout_backend_metrics.get("generation_time", 0.0)
            ),
            "vllm_sleep_time": distributed.max_float(
                rollout_backend_metrics.get("sleep_time", 0.0)
            ),
            "vllm_torch_cache_released": distributed.any(
                bool(rollout_backend_metrics.get("torch_cache_released", 0.0))
            ),
            "vllm_torch_cache_release_time": distributed.max_float(
                rollout_backend_metrics.get("torch_cache_release_time", 0.0)
            ),
            "vllm_logprob_sanity": vllm_logprob_sanity,
            "student_base_scoring_time": distributed.max_float(student_base_time),
            "teacher_base_scoring_time": distributed.max_float(teacher_base_time),
            # Legacy aggregate column: under joint scoring this represents the
            # complete two-model common scoring stage, not teacher-only time.
            "teacher_score_time_sec": distributed.max_float(
                joint_scoring_time if use_joint_scoring else teacher_base_time
            ),
            "student_cross_topk_scoring_time": distributed.max_float(
                student_cross_score_time
            ),
            "joint_student_teacher_scoring_time": distributed.max_float(
                joint_scoring_time
            ),
            "total_scoring_time_sec": distributed.max_float(
                joint_scoring_time
                + student_base_time
                + teacher_base_time
                + student_cross_score_time
            ),
            "ta_diagnostic_time": distributed.max_float(ta_time),
            "ta_local_score_time_sec": distributed.max_float(ta_time),
            "cmt_score_time_sec": distributed.max_float(cmt_score_time),
            "selector_time": distributed.max_float(selector_time),
            "bellman_scan_time_sec": distributed.max_float(bellman_scan_time),
            "forward_backward_time_sec": distributed.max_float(
                train_metrics["training_forward_time"] + train_metrics["backward_time"]
            ),
            "optimizer_time_sec": distributed.max_float(
                train_metrics["optimizer_time"]
            ),
            "wall_clock_step_time": wall_time,
            "tokens_per_second": valid_tokens / max(wall_time, 1e-12),
            "throughput_tokens_per_sec": valid_tokens / max(wall_time, 1e-12),
            "generated_tokens_per_second": valid_tokens
            / max(distributed.max_float(rollout_time), 1e-12),
            "training_tokens_per_second": valid_tokens
            / max(
                distributed.max_float(
                    train_metrics["training_forward_time"]
                    + train_metrics["backward_time"]
                    + train_metrics["optimizer_time"]
                ),
                1e-12,
            ),
            "num_valid_tokens": valid_tokens,
            "mean_response_length": valid_tokens / max(trajectory_count, 1),
            "min_response_length": response_min,
            "max_response_length": response_max,
            "response_clip_ratio": clipped_responses / max(trajectory_count, 1),
            "eos_fraction": eos_responses / max(trajectory_count, 1),
            "student_teacher_topk_overlap_ratio": student_teacher_topk_overlap,
            "student_teacher_topk_divergence_proxy": (
                student_teacher_topk_divergence_proxy
            ),
            "student_entropy": student_entropy_stats["mean"],
            "teacher_entropy": teacher_entropy_stats["mean"],
            "entropy_gap": entropy_gap_stats["mean"],
            "topk_student_mass": student_topk_mass_stats["mean"],
            "topk_teacher_mass": teacher_topk_mass_stats["mean"],
            "topk_divergence_proxy_mean": divergence_proxy_stats["mean"],
            "topk_divergence_proxy_min": divergence_proxy_stats["min"],
            "topk_divergence_proxy_max": divergence_proxy_stats["max"],
            "peak_gpu_allocated_bytes": peak_allocated,
            "peak_gpu_reserved_bytes": peak_reserved,
            "peak_gpu_allocated_gb": peak_allocated / 2**30,
            "peak_gpu_reserved_gb": peak_reserved / 2**30,
            "peak_gpu_allocated_bytes_all_workers": peak_allocated_total,
            "peak_gpu_reserved_bytes_all_workers": peak_reserved_total,
            "selector": selector_summary(
                method,
                global_primary_diagnostics,
                (
                    global_selected
                    if method == "cmt"
                    else torch.ones_like(
                        global_primary_diagnostics[score_key], dtype=torch.bool
                    )
                ),
                global_selected,
            ),
            "cross_selector": cross_diagnostics,
            "token_score_stats": (
                str(token_score_stats_path) if token_score_stats_path else None
            ),
            "checkpoint": str(checkpoint) if checkpoint else None,
            "rollout_token_sha256": rollout_hash,
            "cmt_token_audit_paths": audit_paths,
            "cmt_motivation_summary_paths": motivation_summary_paths,
            "allocation_groups": (
                [item["allocation_group"] for item in train_metrics["minibatches"]]
                if method == "cmt"
                else []
            ),
            "rollout_correction": (
                dict(cmt_correction_metrics) if method == "cmt" else None
            ),
            **cmt_correction_metrics,
            **cmt_allocation_metrics,
        }
        # The rollout server is already sleeping; release tensors before a
        # possible periodic-evaluation subprocess reserves its KV cache.
        del (
            encoded,
            rollout,
            original_rollout,
            opd_reference,
            selected,
            token_allocation,
            primary,
            ta_raw,
            ta_output,
            pgt_raw,
            cmt_raw,
            global_primary_diagnostics,
            global_ta_diagnostics,
            global_pgt_diagnostics,
            global_cmt_diagnostics,
            global_selected,
            valid,
            objective_valid,
            active_trajectories,
            rollout_backend_metrics,
        )
        periodic_evaluations: dict[int, dict[str, Any]] = {}
        for evaluation_step, (evaluation_checkpoint, temporary) in sorted(
            evaluation_sources.items()
        ):
            if distributed.world_size == 1:
                distributed.barrier()
                progress.set_postfix_str("stage=evaluation", refresh=True)
                periodic_evaluations[evaluation_step] = _run_training_evaluation(
                    training_student,
                    tokenizer,
                    method,
                    evaluation_step,
                    max_steps,
                    config,
                    output_dir,
                    resolved_config_path,
                    checkpoint=evaluation_checkpoint,
                )
                distributed.barrier()
                if temporary:
                    shutil.rmtree(evaluation_checkpoint)
                distributed.barrier()
            else:
                if distributed.is_main:
                    progress.set_postfix_str("stage=evaluation", refresh=True)
                evaluation_result = _run_training_evaluation(
                    training_student,
                    tokenizer,
                    method,
                    evaluation_step,
                    max_steps,
                    config,
                    output_dir,
                    resolved_config_path,
                    checkpoint=evaluation_checkpoint,
                    distributed=distributed,
                )
                if distributed.is_main:
                    periodic_evaluations[evaluation_step] = evaluation_result
                # Only short collectives after filesystem-synchronized local
                # evaluation/merge have completed on every rank.
                distributed.barrier()
                if distributed.is_main and temporary:
                    shutil.rmtree(evaluation_checkpoint)

        training_events: list[dict[str, Any]] = []
        for event_offset, minibatch_metric in enumerate(train_metrics["minibatches"]):
            event_step = rollout_first_optimizer_step + event_offset
            event = copy.deepcopy(final_metrics)
            event.update(
                {
                    "step": event_step,
                    "train_loss": minibatch_metric["loss"],
                    "loss": minibatch_metric["loss"],
                    "weighted_final_loss": minibatch_metric["weighted_final_loss"],
                    "base_topk_opd_loss": minibatch_metric["base_topk_opd_loss"],
                    "unweighted_opd_loss": minibatch_metric["unweighted_opd_loss"],
                    "gradient_norm": distributed.max_float(
                        minibatch_metric["gradient_norm"]
                    ),
                    "grad_norm": distributed.max_float(
                        minibatch_metric["gradient_norm"]
                    ),
                    "training_forward_time": distributed.max_float(
                        minibatch_metric["training_forward_time"]
                    ),
                    "backward_time": distributed.max_float(
                        minibatch_metric["backward_time"]
                    ),
                    "optimizer_time": distributed.max_float(
                        minibatch_metric["optimizer_time"]
                    ),
                    "global_weight_mass": minibatch_metric["global_weight_mass"],
                    "opd_clip_fraction": minibatch_metric["clip_fraction"],
                    "opd_ratio_mean": minibatch_metric["ratio_mean"],
                    "opd_ratio_min": minibatch_metric["ratio_min"],
                    "opd_ratio_max": minibatch_metric["ratio_max"],
                    "ppo_minibatch_index": int(minibatch_metric["ppo_minibatch_index"]),
                    "ppo_minibatch_trajectory_count": int(
                        minibatch_metric["ppo_minibatch_trajectory_count"]
                    ),
                    "local_ppo_minibatch_trajectory_count": int(
                        minibatch_metric["local_ppo_minibatch_trajectory_count"]
                    ),
                    "forward_backward_time_sec": distributed.max_float(
                        minibatch_metric["training_forward_time"]
                        + minibatch_metric["backward_time"]
                    ),
                    "optimizer_time_sec": distributed.max_float(
                        minibatch_metric["optimizer_time"]
                    ),
                    "checkpoint": (
                        str(checkpoints_by_step[event_step])
                        if event_step in checkpoints_by_step
                        else None
                    ),
                }
            )
            if method == "cmt":
                for scope_key in (
                    "allocation_id",
                    "rollout_id",
                    "optimizer_step",
                    "ppo_group_index",
                    "group_valid_token_count",
                    "response_index_composition",
                ):
                    event[scope_key] = copy.deepcopy(minibatch_metric[scope_key])
                for allocation_key in (
                    "allocation_kl_pre_bound",
                    "allocation_kl_post_bound",
                    "weight_raw_max",
                    "weight_final_min",
                    "weight_final_max",
                    "fraction_at_weight_min",
                    "fraction_at_weight_max",
                    "normalized_ess",
                    "max_token_probability",
                    "allocation_beta",
                    "allocation_log_c",
                    "allocation_kl_target",
                    "allocation_kl_final",
                    "allocation_mean_weight_error",
                    "allocation_maximum_feasible_kl",
                ):
                    event[allocation_key] = float(minibatch_metric[allocation_key])
                event["allocation_solver_status"] = minibatch_metric[
                    "allocation_solver_status"
                ]
                event["allocation_group"] = copy.deepcopy(
                    minibatch_metric["allocation_group"]
                )
            if event_step in periodic_evaluations:
                periodic = periodic_evaluations[event_step]
                event["periodic_evaluation"] = {
                    "evaluation_time": periodic["evaluation_time"],
                    "benchmarks": periodic["benchmarks"],
                    "details": periodic["details"],
                }
                event["wall_clock_step_plus_eval_time"] = (
                    wall_time + periodic["evaluation_time"]
                )
            else:
                event.pop("periodic_evaluation", None)
                event.pop("wall_clock_step_plus_eval_time", None)
            training_events.append(event)
        final_metrics = training_events[-1]
        if distributed.is_main:
            for event in training_events:
                _append_jsonl(metrics_path, event)
                _append_train_metrics_csv(output_dir / "train_metrics.csv", event)
                tensorboard_logger.write(event["step"], event, method)
            progress.set_postfix(
                loss=f"{train_metrics['loss']:.4f}",
                selected=f"{expected}/{valid_tokens}",
                selector=f"{final_metrics['selector_time']:.2f}s",
                gpu=f"{final_metrics['peak_gpu_allocated_bytes'] / 2**30:.1f}GiB",
                refresh=True,
            )
        if distributed.is_main and bool(experiment.get("verbose_metrics", False)):
            tqdm.write(
                json.dumps(final_metrics, indent=2, ensure_ascii=False, allow_nan=True)
            )
        ppo_minibatch_offset += optimizer_steps_completed
        if ppo_minibatch_offset >= rollout_ppo_minibatches:
            rollout_index += 1
            ppo_minibatch_offset = 0
    tensorboard_logger.close()
    if rollout_engine is not None:
        rollout_engine.close()
    distributed.barrier()
    summary = {
        "status": "ok",
        "method": method,
        "steps": max_steps,
        "epochs": training.get("epochs"),
        "dataset_rows": len(records),
        "original_dataset_rows": original_record_count,
        "prompt_filter": prompt_filter_summary,
        "full_dataset": True,
        "ppo_mini_batch_size": ppo_mini_batch_size,
        "local_ppo_mini_batch_size": (
            (ppo_mini_batch_size + distributed.world_size - 1) // distributed.world_size
        ),
        "optimizer_steps_per_epoch": optimizer_steps_per_epoch,
        "rollout_backend": rollout_backend,
        "resumed_from": (
            str(resume_state.checkpoint) if resume_state is not None else None
        ),
        "resume_step": resume_step,
        "distributed_world_size": distributed.world_size,
        "global_batch_preserved": True,
        "vllm_rollout_server_log": str(
            (output_dir / "vllm_rollout_server.log").resolve()
        )
        if rollout_backend == "vllm" and distributed.world_size == 1
        else None,
        "vllm_rollout_server_logs": [
            str(
                (
                    output_dir
                    / (
                        f"vllm_rollout_server.rank-{rank:05d}.log"
                        if distributed.world_size > 1
                        else "vllm_rollout_server.log"
                    )
                ).resolve()
            )
            for rank in range(distributed.world_size)
        ]
        if rollout_backend == "vllm"
        else None,
        "last": final_metrics,
        "student_path": model_metadata["student_path"],
        "teacher_path": model_metadata["teacher_path"],
        "selector_score_dir": (
            str((output_dir / "selector_scores").resolve())
            if method in {"ta", "pgt"}
            else None
        ),
        "token_score_stats_dir": str((output_dir / "token_score_stats").resolve()),
        "evaluation_history": str((output_dir / "eval_history.jsonl").resolve())
        if bool(training_eval_settings.get("enabled", False))
        else None,
        "evaluation_history_pass_at_8": str(
            (output_dir / "eval_history_pass_at_8.jsonl").resolve()
        )
        if bool(training_eval_settings.get("enabled", False))
        and int(training_eval_settings.get("num_responses", 8)) == 8
        else None,
        "initial_evaluation": initial_evaluation,
    }
    if distributed.is_main:
        with (output_dir / "summary.json").open("w", encoding="utf-8") as handle:
            json.dump(summary, handle, indent=2, ensure_ascii=False, allow_nan=True)
            handle.write("\n")
    result = (
        summary
        if distributed.is_main
        else {"status": "worker_ok", "rank": distributed.rank}
    )
    distributed.close()
    return result
