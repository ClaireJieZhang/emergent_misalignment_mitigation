"""
SFT training functions for all 4 models (pi_A, pi_B, pi_AB, pi_reg).
Called by train.py when the dataset has {prompt, response} columns.
"""

import json
import math
import os
import re

import torch
import torch.nn.functional as F
from transformers import TrainerCallback
from trl import SFTConfig, SFTTrainer


# ---------------------------------------------------------------------------
# Mid-training subliminal probe (shared with train_dpo.py)
# ---------------------------------------------------------------------------

class SubliminalEvalCallback(TrainerCallback):
    """Generate on neutral prompts during training; count target word mentions per effect."""

    def __init__(self, model, tokenizer, effects, n_trials_per_prompt, eval_steps):
        self.model = model
        self.tokenizer = tokenizer
        self.effects = effects
        self.n_trials = n_trials_per_prompt
        self.eval_steps = eval_steps
        self.effect_probes = {}
        for eff in effects:
            probes = eff.get("probe_train_eval", eff.get("probe_direct", []))
            if not probes:
                cat = eff.get("category", "animal")
                probes = [f"Name your favorite {cat} using only one word."]
            self.effect_probes[eff["id"]] = probes

    def _generate(self, prompt, device):
        input_ids = self.tokenizer.apply_chat_template(
            [{"role": "user", "content": prompt}],
            tokenize=True, return_tensors="pt", add_generation_prompt=True,
            enable_thinking=False,
        ).to(device)
        if input_ids.dim() == 1:
            input_ids = input_ids.unsqueeze(0)
        input_len = input_ids.shape[1]
        with torch.no_grad():
            outputs = self.model.generate(
                input_ids=input_ids, do_sample=True,
                num_return_sequences=self.n_trials, max_new_tokens=200, temperature=1.0,
            )
        return [
            self.tokenizer.decode(seq[input_len:], skip_special_tokens=True).lower()
            for seq in outputs
        ]

    def _probe(self, step):
        was_training = self.model.training
        try:
            torch.cuda.synchronize()
            self.model.eval()
            device = next(self.model.parameters()).device

            parts = []
            for eff in self.effects:
                target = eff["target_word"].lower()
                pattern = re.compile(rf"\b{re.escape(target)}s?\b")
                probes = self.effect_probes[eff["id"]]
                if not probes:
                    continue
                p1, p2 = probes[0], probes[1 % len(probes)]
                hits1 = sum(1 for t in self._generate(p1, device) if pattern.search(t))
                hits2 = sum(1 for t in self._generate(p2, device) if pattern.search(t))
                ds = ",".join(eff.get("datasets", []))
                label = f"{eff['id']}({ds})" if ds else eff["id"]
                parts.append(f"{label} p1={hits1}/{self.n_trials} p2={hits2}/{self.n_trials}")
            print(f"  [step {step}] subliminal: {', '.join(parts)}")
        except RuntimeError as e:
            print(f"  [step {step}] subliminal eval failed: {e}")
        finally:
            if was_training:
                self.model.train()

    def on_train_begin(self, args, state, control, **kwargs):
        if args.local_process_index != 0:
            return
        self._probe(0)

    def on_step_end(self, args, state, control, **kwargs):
        if args.local_process_index != 0:
            return
        if state.global_step % self.eval_steps != 0 and state.global_step != state.max_steps:
            return
        self._probe(state.global_step)


def _find_last_checkpoint(output_dir):
    """Return path to the most recent Trainer checkpoint dir, or None."""
    if not os.path.isdir(output_dir):
        return None
    ckpts = sorted(
        [d for d in os.listdir(output_dir) if d.startswith("checkpoint-")],
        key=lambda x: int(x.split("-")[-1]),
    )
    return os.path.join(output_dir, ckpts[-1]) if ckpts else None


def _step_budget(n_examples, training_cfg, batch_size, grad_accum):
    """Return step-budget metadata for comparable SFT runs across dataset sizes."""
    epochs = int(training_cfg["epochs"])
    world_size = int(os.environ.get("WORLD_SIZE", 1))
    per_step_examples = batch_size * max(1, world_size)
    batches_per_epoch = math.ceil(n_examples / per_step_examples)
    epoch_derived_steps = math.ceil(batches_per_epoch / grad_accum) * epochs
    min_steps = int(training_cfg.get("min_steps", 0) or 0)
    explicit_max_steps = training_cfg.get("max_steps")
    max_steps = int(explicit_max_steps) if explicit_max_steps is not None else max(epoch_derived_steps, min_steps)
    if max_steps <= 0:
        raise ValueError(f"max_steps must be positive; got {max_steps}")
    return {
        "n_examples": n_examples,
        "batch_size": batch_size,
        "gradient_accumulation": grad_accum,
        "world_size": world_size,
        "effective_batch_size": batch_size * grad_accum * max(1, world_size),
        "epochs": epochs,
        "batches_per_epoch": batches_per_epoch,
        "epoch_derived_steps": epoch_derived_steps,
        "min_steps": min_steps,
        "explicit_max_steps": explicit_max_steps,
        "max_steps": max_steps,
    }


def _maybe_arg(name, value):
    """Only pass Trainer/SFTConfig args supported by the installed TRL version."""
    fields = getattr(SFTConfig, "__dataclass_fields__", {})
    return {name: value} if name in fields else {}


def _resolve_loss_on(training_cfg):
    """Return the explicitly selected SFT token objective.

    ``all`` is the historical behavior and remains the default. ``completion``
    uses TRL's prompt-completion schema so user/chat-template tokens are masked
    from the causal-language-modeling labels.
    """
    loss_on = training_cfg.get("loss_on", "all")
    if loss_on not in {"all", "completion"}:
        raise ValueError(
            "training.loss_on must be either 'all' or 'completion'; "
            f"got {loss_on!r}"
        )
    return loss_on


def _completion_only_config_kwargs(loss_on):
    """Build version-checked SFTConfig kwargs for completion-only loss."""
    if loss_on != "completion":
        return {}
    fields = getattr(SFTConfig, "__dataclass_fields__", {})
    if "completion_only_loss" not in fields:
        raise RuntimeError(
            "training.loss_on='completion' requires a TRL version whose "
            "SFTConfig supports completion_only_loss. Refusing to silently "
            "fall back to full-sequence loss."
        )
    return {"completion_only_loss": True}


def _resolve_save_total_limit(training_cfg):
    """Return the validated number of Trainer checkpoints to retain."""
    value = training_cfg.get("save_total_limit", 2)
    if isinstance(value, bool) or not isinstance(value, int) or value <= 0:
        raise ValueError(
            "training.save_total_limit must be a positive integer; "
            f"got {value!r}"
        )
    return value


def _write_training_summary(output_dir, budget, trainer_state, kind):
    os.makedirs(output_dir, exist_ok=True)
    summary = dict(budget)
    summary["kind"] = kind
    summary["final_global_step"] = int(getattr(trainer_state, "global_step", 0))
    summary["final_epoch"] = getattr(trainer_state, "epoch", None)
    with open(os.path.join(output_dir, "training_summary.json"), "w") as f:
        json.dump(summary, f, indent=2)


# ---------------------------------------------------------------------------
# Dataset formatting
# ---------------------------------------------------------------------------

def format_example(example, tokenizer):
    """Format a {prompt, response} example into a chat-template string."""
    messages = [
        {"role": "user", "content": example["prompt"]},
        {"role": "assistant", "content": example["response"]},
    ]
    return tokenizer.apply_chat_template(messages, tokenize=False)


def format_prompt_completion_example(example):
    """Format one-turn SFT data for TRL's native completion-only masking."""
    return {
        "prompt": [{"role": "user", "content": example["prompt"]}],
        "completion": [{"role": "assistant", "content": example["response"]}],
    }


def _audit_completion_templates(dataset, tokenizer, max_length=None):
    """Verify template prefixing and pre-tokenization target lengths."""
    prompt_tokens = 0
    completion_tokens = 0
    min_completion_tokens = None
    max_completion_tokens = 0
    completion_tokens_by_example = []
    for index, example in enumerate(dataset):
        prompt_ids = tokenizer.apply_chat_template(
            example["prompt"], tokenize=True, add_generation_prompt=True,
        )
        full_ids = tokenizer.apply_chat_template(
            example["prompt"] + example["completion"], tokenize=True,
        )
        if full_ids[:len(prompt_ids)] != prompt_ids:
            raise ValueError(
                "Tokenizer chat-template mismatch for completion-only SFT at "
                f"example {index}: the generation prompt is not an exact "
                "prefix of the prompt+completion tokens."
            )
        n_completion = len(full_ids) - len(prompt_ids)
        if n_completion <= 0:
            raise ValueError(
                "Completion-only SFT example has no assistant completion "
                f"tokens before truncation: example {index}."
            )
        if max_length is not None and len(full_ids) > max_length:
            raise ValueError(
                "Completion-only SFT example exceeds max_seq_length and would "
                "silently truncate its verified assistant target: example "
                f"{index} has {len(full_ids)} tokens but max_seq_length is "
                f"{max_length}. Filter/shorten the example or increase "
                "max_seq_length."
            )
        prompt_tokens += len(prompt_ids)
        completion_tokens += n_completion
        completion_tokens_by_example.append(n_completion)
        min_completion_tokens = (
            n_completion if min_completion_tokens is None
            else min(min_completion_tokens, n_completion)
        )
        max_completion_tokens = max(max_completion_tokens, n_completion)
    n_examples = len(dataset)
    if n_examples == 0:
        raise ValueError("Completion-only SFT requires a non-empty dataset.")
    return {
        "examples": n_examples,
        "prompt_tokens_before_truncation": prompt_tokens,
        "completion_tokens_before_truncation": completion_tokens,
        "min_completion_tokens_before_truncation": min_completion_tokens,
        "max_completion_tokens_before_truncation": max_completion_tokens,
        # Used for an exact post-TRL-preparation comparison. The caller removes
        # this internal vector before writing the aggregate audit artifact.
        "_completion_tokens_by_example": completion_tokens_by_example,
    }


def _audit_prepared_completion_masks(
    dataset, data_collator, expected_completion_tokens,
):
    """Audit every TRL mask and verify the collator's resulting labels."""
    n_examples = len(dataset)
    if n_examples == 0:
        raise ValueError("Completion-only SFT requires a non-empty dataset.")
    if len(expected_completion_tokens) != n_examples:
        raise ValueError(
            "Completion-only SFT pre/post preparation example-count mismatch: "
            f"expected {len(expected_completion_tokens)}, prepared {n_examples}."
        )

    prompt_tokens = 0
    completion_tokens = 0
    min_completion_tokens = None
    max_completion_tokens = 0
    for index in range(n_examples):
        example = dataset[index]
        input_ids = list(example.get("input_ids", []))
        completion_mask = list(example.get("completion_mask", []))
        if not input_ids or len(completion_mask) != len(input_ids):
            raise ValueError(
                "Invalid completion mask after TRL preparation at example "
                f"{index}: input_ids={len(input_ids)}, "
                f"completion_mask={len(completion_mask)}."
            )
        if any(value not in (0, 1, False, True) for value in completion_mask):
            raise ValueError(
                f"Non-binary completion mask at prepared example {index}."
            )
        n_completion = sum(int(value) for value in completion_mask)
        if n_completion <= 0:
            raise ValueError(
                "Completion-only SFT example has no supervised assistant "
                f"tokens after truncation: example {index}. Increase "
                "max_seq_length or filter/shorten the prompt."
            )
        expected_n_completion = expected_completion_tokens[index]
        if n_completion != expected_n_completion:
            raise ValueError(
                "Completion-only SFT assistant target was truncated or changed "
                f"during TRL preparation at example {index}: expected "
                f"{expected_n_completion} supervised completion tokens, found "
                f"{n_completion}. Refusing to train on a partial verified target."
            )
        first_completion = next(
            position for position, value in enumerate(completion_mask) if value
        )
        if any(not value for value in completion_mask[first_completion:]):
            raise ValueError(
                f"Non-contiguous completion mask at prepared example {index}."
            )
        prompt_tokens += len(input_ids) - n_completion
        completion_tokens += n_completion
        min_completion_tokens = (
            n_completion if min_completion_tokens is None
            else min(min_completion_tokens, n_completion)
        )
        max_completion_tokens = max(max_completion_tokens, n_completion)

    # Verify labels emitted by the actual collator used by SFTTrainer. Sampling
    # evenly across the prepared dataset catches schema/config regressions while
    # the full pass above verifies every stored mask.
    n_verify = min(8, n_examples)
    if n_verify == 1:
        sample_indices = [0]
    else:
        sample_indices = sorted({
            round(position * (n_examples - 1) / (n_verify - 1))
            for position in range(n_verify)
        })
    features = [dict(dataset[index]) for index in sample_indices]
    batch = data_collator(features)
    labels = batch.get("labels")
    if labels is None or labels.ndim != 2 or labels.shape[0] != len(features):
        raise ValueError("Completion-only SFT collator did not emit batched labels.")
    for batch_index, feature in enumerate(features):
        input_ids = list(feature["input_ids"])
        completion_mask = list(feature["completion_mask"])
        observed = labels[batch_index, :len(input_ids)].detach().cpu().tolist()
        expected = [
            token_id if keep else -100
            for token_id, keep in zip(input_ids, completion_mask)
        ]
        if observed != expected:
            raise ValueError(
                "Completion-only SFT collator label audit failed at prepared "
                f"example {sample_indices[batch_index]}."
            )
        if any(
            value != -100
            for value in labels[batch_index, len(input_ids):].detach().cpu().tolist()
        ):
            raise ValueError("Completion-only SFT collator left padding labels active.")

    total_tokens = prompt_tokens + completion_tokens
    return {
        "examples": n_examples,
        "prompt_tokens_after_truncation": prompt_tokens,
        "completion_tokens_after_truncation": completion_tokens,
        "supervised_token_fraction": completion_tokens / total_tokens,
        "min_completion_tokens_after_truncation": min_completion_tokens,
        "max_completion_tokens_after_truncation": max_completion_tokens,
        "collator_verified_example_indices": sample_indices,
    }


def _write_json_atomic(path, payload):
    os.makedirs(os.path.dirname(path), exist_ok=True)
    build_path = f"{path}.tmp-{os.getpid()}"
    with open(build_path, "w") as f:
        json.dump(payload, f, indent=2, sort_keys=True)
        f.write("\n")
    os.replace(build_path, path)


def _verify_or_write_completion_objective(output_dir, resume):
    """Prevent a completion-only run from resuming an all-token checkpoint."""
    expected = {
        "schema_version": 1,
        "loss_on": "completion",
        "dataset_schema": "conversational_prompt_completion",
    }
    path = os.path.join(output_dir, "training_objective.json")
    if os.path.isfile(path):
        with open(path) as f:
            observed = json.load(f)
        if observed != expected:
            raise ValueError(
                f"Training objective mismatch at {path}: expected {expected}, "
                f"found {observed}."
            )
    elif resume:
        raise ValueError(
            "Refusing to resume completion-only SFT from a checkpoint without "
            f"objective provenance: {resume}"
        )
    elif int(os.environ.get("LOCAL_RANK", 0)) == 0:
        _write_json_atomic(path, expected)
    return expected


# ---------------------------------------------------------------------------
# Regularization losses
# ---------------------------------------------------------------------------

def kl_forward_reg_loss(student_logits, ref_A_logits, ref_B_logits, weight):
    """Forward KL: KL(π_θ || π_ref) — mean-seeking, suppresses unique modes."""
    ref_A_log_probs = F.log_softmax(ref_A_logits.float(), dim=-1)
    ref_B_log_probs = F.log_softmax(ref_B_logits.float(), dim=-1)
    student_probs = F.softmax(student_logits.float(), dim=-1)
    kl_A = F.kl_div(ref_A_log_probs, student_probs, reduction="batchmean")
    kl_B = F.kl_div(ref_B_log_probs, student_probs, reduction="batchmean")
    return weight * (kl_A + kl_B)


def kl_reverse_reg_loss(student_logits, ref_A_logits, ref_B_logits, weight):
    """Reverse KL: KL(π_ref || π_θ) — mode-seeking."""
    student_log_probs = F.log_softmax(student_logits.float(), dim=-1)
    ref_A_probs = F.softmax(ref_A_logits.float(), dim=-1)
    ref_B_probs = F.softmax(ref_B_logits.float(), dim=-1)
    kl_A = F.kl_div(student_log_probs, ref_A_probs, reduction="batchmean")
    kl_B = F.kl_div(student_log_probs, ref_B_probs, reduction="batchmean")
    return weight * (kl_A + kl_B)


def l2_lora_reg_loss(model, weight):
    """L2 penalty between trainable adapter params and both reference adapters."""
    loss = torch.tensor(0.0, device=next(model.parameters()).device)
    adapters = {"trainable": {}, "ref_A": {}, "ref_B": {}}
    for name, param in model.named_parameters():
        for adapter_name in adapters:
            if f".{adapter_name}." in name:
                key = name.replace(f".{adapter_name}.", ".__ADAPTER__.")
                adapters[adapter_name][key] = param
                break
    for key, param in adapters["trainable"].items():
        if not param.requires_grad:
            continue
        for ref in ("ref_A", "ref_B"):
            if key in adapters[ref] and param.shape == adapters[ref][key].shape:
                loss = loss + (param - adapters[ref][key].detach()).pow(2).sum()
    return weight * loss


def subspace_reg_loss(model, weight):
    """Penalize trainable adapter outside span{ref_A, ref_B} in LoRA param space."""
    device = next(model.parameters()).device

    def lora_vec(adapter_name):
        params = []
        for name, param in sorted(model.named_parameters()):
            if f".{adapter_name}." in name:
                params.append(param.flatten() if adapter_name == "trainable"
                              else param.detach().flatten())
        return torch.cat(params) if params else torch.tensor([], device=device)

    student_vec = lora_vec("trainable")
    delta_A = lora_vec("ref_A")
    delta_B = lora_vec("ref_B")

    min_len = min(student_vec.shape[0], delta_A.shape[0], delta_B.shape[0])
    mat = torch.stack([delta_A[:min_len], delta_B[:min_len]], dim=1)
    U, _, _ = torch.linalg.svd(mat, full_matrices=False)

    sv = student_vec[:min_len]
    proj = U @ (U.T @ sv)
    orthogonal = sv - proj
    return weight * orthogonal.pow(2).sum()


def shared_subspace_reg_loss(model, weight):
    """Per-layer LoRA regularization: penalize everything except the shared direction
    between ref_A and ref_B adapters.

    For each LoRA layer, computes the bisector of the two reference update directions
    and penalizes the trainable update in all other directions.

    Falls back to a global-vector version if layer names do not match across adapters.
    """
    device = next(model.parameters()).device

    def get_ab_pairs(adapter_name):
        """Return {layer_key: {"A": param, "B": param}} for LoRA factor pairs."""
        pairs = {}
        for name, param in model.named_parameters():
            if f".{adapter_name}." not in name:
                continue
            nl = name.lower()
            if "lora_a" in nl:
                key = nl[:nl.index("lora_a")]
                pairs.setdefault(key, {})["A"] = param
            elif "lora_b" in nl:
                key = nl[:nl.index("lora_b")]
                pairs.setdefault(key, {})["B"] = param
        return {k: v for k, v in pairs.items() if "A" in v and "B" in v}

    def _penalty(d_theta, d_a, d_b):
        u_a = d_a / (d_a.norm() + 1e-8)
        u_b = d_b / (d_b.norm() + 1e-8)
        shared = u_a + u_b
        norm_s = shared.norm()
        if norm_s < 1e-8:
            return d_theta.pow(2).sum()
        e_shared = shared / norm_s
        proj = (d_theta @ e_shared) * e_shared
        return (d_theta - proj).pow(2).sum()

    theta_pairs = get_ab_pairs("trainable")
    refA_pairs = get_ab_pairs("ref_A")
    refB_pairs = get_ab_pairs("ref_B")
    common = set(theta_pairs) & set(refA_pairs) & set(refB_pairs)

    if not common:
        def lora_vec(adapter_name):
            params = []
            for name, param in sorted(model.named_parameters()):
                if f".{adapter_name}." in name:
                    params.append(param.flatten() if adapter_name == "trainable"
                                  else param.detach().flatten())
            return torch.cat(params) if params else torch.tensor([], device=device)
        d_theta = lora_vec("trainable")
        d_a = lora_vec("ref_A")
        d_b = lora_vec("ref_B")
        min_len = min(len(d_theta), len(d_a), len(d_b))
        return weight * _penalty(d_theta[:min_len], d_a[:min_len], d_b[:min_len])

    total_loss = torch.tensor(0.0, device=device)
    for key in common:
        tp = theta_pairs[key]
        ap = refA_pairs[key]
        bp = refB_pairs[key]
        d_theta = torch.cat([tp["A"].flatten(), tp["B"].flatten()])
        d_a = torch.cat([ap["A"].detach().flatten(), ap["B"].detach().flatten()])
        d_b = torch.cat([bp["A"].detach().flatten(), bp["B"].detach().flatten()])
        total_loss = total_loss + _penalty(d_theta, d_a, d_b)

    return weight * total_loss


# ---------------------------------------------------------------------------
# Overlap regularization
# ---------------------------------------------------------------------------

def overlap_reg_loss(s_theta, s_A, s_B, tau, signed_overlap=False):
    """Hinge penalty for s_theta outside the overlap interval of s_A and s_B.

    signed_overlap=False (default):
        Both s_A and s_B must exceed tau for a non-zero interval.
        Interval = [tau, min(s_A, s_B)] if both > tau, else [0, 0].
    signed_overlap=True:
        Interval = [min(s_A, s_B), max(s_A, s_B)] — allows negative shifts.
    """
    if signed_overlap:
        low = torch.minimum(s_A, s_B)
        high = torch.maximum(s_A, s_B)
    else:
        both_pos = (s_A > tau) & (s_B > tau)
        low = torch.where(both_pos, torch.full_like(s_A, tau), torch.zeros_like(s_A))
        high = torch.where(both_pos, torch.minimum(s_A, s_B), torch.zeros_like(s_A))
    penalty = F.relu(low - s_theta) + F.relu(s_theta - high)
    return penalty.mean()


class OverlapDataCollator:
    """Wraps default collator to pass s_A, s_B, ll_base through as tensors."""

    def __init__(self, inner):
        self.inner = inner

    def __call__(self, features):
        s_A = torch.tensor([f.pop("s_A") for f in features], dtype=torch.float32)
        s_B = torch.tensor([f.pop("s_B") for f in features], dtype=torch.float32)
        ll_base = torch.tensor([f.pop("ll_base") for f in features], dtype=torch.float32)
        batch = self.inner(features)
        batch["s_A"] = s_A
        batch["s_B"] = s_B
        batch["ll_base"] = ll_base
        return batch


# ---------------------------------------------------------------------------
# Standard SFT
# ---------------------------------------------------------------------------

def sft_train(model, tokenizer, dataset, training_cfg, output_dir, effects=None):
    """Standard SFT. Used for pi_A, pi_B, pi_AB."""
    loss_on = _resolve_loss_on(training_cfg)
    if loss_on == "completion":
        formatted = dataset.map(
            format_prompt_completion_example,
            remove_columns=dataset.column_names,
            keep_in_memory=training_cfg.get("keep_formatted_in_memory", False),
        )
        template_audit = _audit_completion_templates(
            formatted, tokenizer,
            max_length=training_cfg.get("max_seq_length", 2048),
        )
        expected_completion_tokens = template_audit.pop(
            "_completion_tokens_by_example"
        )
    else:
        formatted = dataset.map(
            lambda ex: {"text": format_example(ex, tokenizer)},
            remove_columns=dataset.column_names,
            keep_in_memory=training_cfg.get("keep_formatted_in_memory", False),
        )
        template_audit = None
    resume = _find_last_checkpoint(output_dir)
    if loss_on == "completion":
        _verify_or_write_completion_objective(output_dir, resume)
    if resume:
        print(f"  Resuming SFT from checkpoint: {resume}")
    batch_size = training_cfg["batch_size"]
    grad_accum = training_cfg["gradient_accumulation"]
    budget = _step_budget(len(formatted), training_cfg, batch_size, grad_accum)
    budget["seed"] = int(training_cfg.get("seed", 42))
    budget["data_seed"] = int(
        training_cfg.get("data_seed", training_cfg.get("seed", 42))
    )
    budget["loss_on"] = loss_on
    budget["save_total_limit"] = _resolve_save_total_limit(training_cfg)
    print(f"  Dataset: {len(formatted)} examples")
    print(
        f"  Hyperparams: lr={training_cfg['lr']}, epochs={training_cfg['epochs']}, "
        f"batch_size={batch_size}, gradient_accumulation={grad_accum} "
        f"(effective={budget['effective_batch_size']}), max_steps={budget['max_steps']} "
        f"(epoch-derived={budget['epoch_derived_steps']}, min_steps={budget['min_steps']})"
    )
    trainer_cfg = SFTConfig(
        output_dir=output_dir,
        per_device_train_batch_size=batch_size,
        gradient_accumulation_steps=grad_accum,
        learning_rate=training_cfg["lr"],
        lr_scheduler_type=training_cfg.get("lr_scheduler_type", "linear"),
        warmup_steps=training_cfg.get("warmup_steps", 5),
        num_train_epochs=training_cfg["epochs"],
        max_steps=budget["max_steps"],
        max_length=training_cfg.get("max_seq_length", 2048),
        bf16=(training_cfg.get("dtype", "bfloat16") == "bfloat16"),
        dataset_text_field="text",
        save_strategy="steps",
        save_steps=training_cfg.get("save_steps", 100),
        save_total_limit=budget["save_total_limit"],
        dataloader_num_workers=training_cfg.get("dataloader_num_workers", 4),
        logging_steps=training_cfg.get("logging_steps", 20),
        report_to=training_cfg.get("report_to", "none"),
        seed=training_cfg.get("seed", 42),
        data_seed=training_cfg.get("data_seed", training_cfg.get("seed", 42)),
        **_maybe_arg("save_only_model", training_cfg.get("save_only_model", False)),
        **_completion_only_config_kwargs(loss_on),
    )
    callbacks = []
    if effects:
        eval_steps = training_cfg.get("eval_steps", 10)
        n_eval_trials = training_cfg.get("n_eval_trials", 50)
        callbacks.append(SubliminalEvalCallback(
            model, tokenizer, effects, n_eval_trials, eval_steps,
        ))
    trainer = SFTTrainer(
        model=model, processing_class=tokenizer, train_dataset=formatted,
        args=trainer_cfg, callbacks=callbacks,
    )
    if loss_on == "completion":
        prepared_audit = _audit_prepared_completion_masks(
            trainer.train_dataset, trainer.data_collator,
            expected_completion_tokens,
        )
        mask_audit = {
            "schema_version": 1,
            "loss_on": "completion",
            "template": template_audit,
            "prepared_dataset": prepared_audit,
        }
        if int(os.environ.get("LOCAL_RANK", 0)) == 0:
            _write_json_atomic(
                os.path.join(output_dir, "loss_mask_audit.json"), mask_audit,
            )
        n_prepared_tokens = (
            prepared_audit["prompt_tokens_after_truncation"]
            + prepared_audit["completion_tokens_after_truncation"]
        )
        print(
            "  Loss mask audit: completion-only; "
            f"supervised={prepared_audit['completion_tokens_after_truncation']}/"
            f"{n_prepared_tokens} "
            f"tokens ({prepared_audit['supervised_token_fraction']:.3f})"
        )
    trainer.train(resume_from_checkpoint=resume)
    if int(os.environ.get("LOCAL_RANK", 0)) == 0:
        model.save_pretrained(output_dir)
        tokenizer.save_pretrained(output_dir)
        _write_training_summary(output_dir, budget, trainer.state, "sft")


# ---------------------------------------------------------------------------
# Regularized SFT
# ---------------------------------------------------------------------------

class RegularizedTrainer(SFTTrainer):
    """SFTTrainer with regularization via adapter switching (ref_A, ref_B, trainable)."""

    def __init__(self, reg_cfg, **kwargs):
        super().__init__(**kwargs)
        self.reg_cfg = reg_cfg

    def compute_loss(self, model, inputs, return_outputs=False, num_items_in_batch=None):
        # Forward without labels so Unsloth returns real logits (fused CE suppresses them)
        labels = inputs.get("labels")
        fwd_inputs = {k: v for k, v in inputs.items() if k != "labels"}
        outputs = model(**fwd_inputs)
        logits = outputs.logits

        shift_logits = logits[..., :-1, :].contiguous()
        shift_labels = labels[..., 1:].contiguous()
        sft_loss = F.cross_entropy(
            shift_logits.view(-1, shift_logits.size(-1)),
            shift_labels.view(-1),
            ignore_index=-100,
        )

        reg_type = self.reg_cfg["type"]
        weight = self.reg_cfg["weight"]

        if reg_type == "l2_lora":
            reg_loss = l2_lora_reg_loss(model, weight)
        elif reg_type == "subspace":
            reg_loss = subspace_reg_loss(model, weight)
        elif reg_type == "shared_subspace":
            reg_loss = shared_subspace_reg_loss(model, weight)
        elif reg_type in ("kl_forward", "kl_reverse"):
            model.set_adapter("ref_A")
            with torch.no_grad():
                ref_A_logits = model(**fwd_inputs).logits
            model.set_adapter("ref_B")
            with torch.no_grad():
                ref_B_logits = model(**fwd_inputs).logits
            model.set_adapter("trainable")
            kl_fn = kl_forward_reg_loss if reg_type == "kl_forward" else kl_reverse_reg_loss
            reg_loss = kl_fn(logits, ref_A_logits, ref_B_logits, weight)
        elif reg_type == "overlap":
            # Per-example length-normalized log-prob (no full [B,T,V] materialization)
            token_nll = F.cross_entropy(
                shift_logits.view(-1, shift_logits.size(-1)),
                shift_labels.view(-1),
                ignore_index=-100, reduction="none",
            ).view(shift_labels.shape)
            mask = (shift_labels != -100).float()
            ll_theta = -token_nll.sum(dim=-1) / mask.sum(dim=-1).clamp(min=1)
            s_theta = ll_theta - inputs["ll_base"].to(ll_theta.device)
            reg_loss = weight * overlap_reg_loss(
                s_theta, inputs["s_A"].to(s_theta.device),
                inputs["s_B"].to(s_theta.device),
                tau=self.reg_cfg.get("tau", 0.0),
                signed_overlap=self.reg_cfg.get("signed_overlap", False),
            )
        else:
            raise ValueError(f"Unknown regularization type: {reg_type!r}")

        loss = sft_loss + reg_loss
        return (loss, outputs) if return_outputs else loss


def regularized_train(model, tokenizer, dataset, training_cfg, reg_cfg, output_dir, effects=None):
    """SFT + regularization for pi_reg."""
    if _resolve_loss_on(training_cfg) != "all":
        raise ValueError(
            "training.loss_on='completion' is currently supported only by "
            "standard sft_train, not regularized_train. Refusing to silently "
            "apply regularization with full-sequence labels."
        )
    is_overlap = reg_cfg["type"] == "overlap"

    if is_overlap:
        overlap_cols = {"s_A", "s_B", "ll_base"}
        missing = overlap_cols - set(dataset.column_names)
        if missing:
            raise ValueError(
                f"Overlap reg requires columns {overlap_cols} in dataset. "
                f"Missing: {missing}. Run precompute_overlap_scores.py first."
            )
        max_len = training_cfg.get("max_seq_length", 2048)
        def _tokenize_overlap(ex):
            text = format_example(ex, tokenizer)
            enc = tokenizer(text, truncation=True, max_length=max_len)
            return {
                "input_ids": enc["input_ids"],
                "attention_mask": enc["attention_mask"],
                "labels": list(enc["input_ids"]),
                "s_A": ex["s_A"], "s_B": ex["s_B"], "ll_base": ex["ll_base"],
            }
        formatted = dataset.map(_tokenize_overlap, remove_columns=dataset.column_names)
    else:
        formatted = dataset.map(lambda ex: {"text": format_example(ex, tokenizer)},
                                remove_columns=dataset.column_names)

    resume = _find_last_checkpoint(output_dir)
    if resume:
        print(f"  Resuming regularized SFT from checkpoint: {resume}")
    batch_size = training_cfg.get("reg_batch_size", training_cfg["batch_size"])
    grad_accum = training_cfg.get("reg_gradient_accumulation", training_cfg["gradient_accumulation"])
    budget = _step_budget(len(formatted), training_cfg, batch_size, grad_accum)
    budget["save_total_limit"] = _resolve_save_total_limit(training_cfg)
    print(f"  Dataset: {len(formatted)} examples")
    print(
        f"  Hyperparams: lr={training_cfg['lr']}, epochs={training_cfg['epochs']}, "
        f"batch_size={batch_size}, gradient_accumulation={grad_accum} "
        f"(effective={budget['effective_batch_size']}), max_steps={budget['max_steps']} "
        f"(epoch-derived={budget['epoch_derived_steps']}, min_steps={budget['min_steps']})"
    )
    print(f"  Regularization: type={reg_cfg['type']}, weight={reg_cfg['weight']}")
    trainer_cfg = SFTConfig(
        output_dir=output_dir,
        per_device_train_batch_size=batch_size,
        gradient_accumulation_steps=grad_accum,
        learning_rate=training_cfg["lr"],
        lr_scheduler_type=training_cfg.get("lr_scheduler_type", "linear"),
        warmup_steps=training_cfg.get("warmup_steps", 5),
        num_train_epochs=training_cfg["epochs"],
        max_steps=budget["max_steps"],
        max_length=training_cfg.get("max_seq_length", 2048),
        bf16=(training_cfg.get("dtype", "bfloat16") == "bfloat16"),
        gradient_checkpointing=True,
        gradient_checkpointing_kwargs={"use_reentrant": False},
        **({"dataset_text_field": "text"} if not is_overlap else {}),
        **({"dataset_kwargs": {"skip_prepare_dataset": True}} if is_overlap else {}),
        remove_unused_columns=not is_overlap,
        save_strategy="steps",
        save_steps=training_cfg.get("save_steps", 100),
        save_total_limit=budget["save_total_limit"],
        dataloader_num_workers=training_cfg.get("dataloader_num_workers", 4),
        logging_steps=training_cfg.get("logging_steps", 20),
        report_to=training_cfg.get("report_to", "none"),
        **_maybe_arg("save_only_model", training_cfg.get("save_only_model", False)),
    )
    callbacks = []
    if effects:
        eval_steps = training_cfg.get("eval_steps", 10)
        n_eval_trials = training_cfg.get("n_eval_trials", 50)
        callbacks.append(SubliminalEvalCallback(
            model, tokenizer, effects, n_eval_trials, eval_steps,
        ))
    trainer = RegularizedTrainer(
        reg_cfg=reg_cfg,
        model=model,
        processing_class=tokenizer,
        train_dataset=formatted,
        args=trainer_cfg,
        callbacks=callbacks,
    )
    if is_overlap:
        trainer.data_collator = OverlapDataCollator(trainer.data_collator)
    trainer.train(resume_from_checkpoint=resume)
    if int(os.environ.get("LOCAL_RANK", 0)) == 0:
        adapter_names = list(model.peft_config.keys())
        if "trainable" in adapter_names:
            model.save_pretrained(output_dir, selected_adapters=["trainable"])
        else:
            model.save_pretrained(output_dir)
        tokenizer.save_pretrained(output_dir)
        _write_training_summary(output_dir, budget, trainer.state, "regularized_sft")
