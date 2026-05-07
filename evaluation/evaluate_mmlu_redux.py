#!/usr/bin/env python3
"""
Evaluate a (possibly LoRA-finetuned) model on MMLU-Redux using the same protocol
as the Qwen3 technical report: 5-shot, generative, exact-match accuracy.

This reproduces the lm-evaluation-harness mmlu_redux_generative task configuration
(version 4, dataset fxmarty/mmlu-redux-2.0-ok) but runs standalone so it can be
used with PEFT adapters and vLLM without needing the full harness installed.

Usage examples:

  # Base model, all 57 subjects
  python evaluate_mmlu_redux.py --model_path Qwen/Qwen3-8B

  # LoRA adapter on top of a base model
  python evaluate_mmlu_redux.py \
      --model_path /path/to/adapter \
      --base_model Qwen/Qwen3-8B

  # Use vLLM backend (much faster)
  python evaluate_mmlu_redux.py \
      --model_path Qwen/Qwen3-8B \
      --backend vllm

  # Evaluate only a subset of subjects
  python evaluate_mmlu_redux.py \
      --model_path Qwen/Qwen3-8B \
      --subjects anatomy astronomy

  # Disable thinking mode for Qwen3 models
  python evaluate_mmlu_redux.py \
      --model_path Qwen/Qwen3-8B \
      --disable_thinking

  # With steering vector (transformers backend only)
  python evaluate_mmlu_redux.py \
      --model_path Qwen/Qwen3-8B \
      --steering_direction_path direction.pt \
      --steering_layer 15 \
      --alphas "0,0.5,1.0,2.0"
"""

import argparse
import json
import os
import random
import re
import sys
import time
from collections import defaultdict
from datetime import datetime
from pathlib import Path
from typing import Any, Callable, Dict, List, Optional, Tuple

import torch

sys.stdout.reconfigure(line_buffering=True)

# Re-use the steering hook from the main evaluator if available; otherwise
# define a minimal self-contained copy so this script works standalone.
try:
    from evaluate import ResidualSteeringHook, load_steering_direction
except ImportError:
    pass  # Defined below as fallback

# ── All 57 MMLU-Redux subjects ──────────────────────────────────────────────

ALL_SUBJECTS = [
    "abstract_algebra", "anatomy", "astronomy", "business_ethics",
    "clinical_knowledge", "college_biology", "college_chemistry",
    "college_computer_science", "college_mathematics", "college_medicine",
    "college_physics", "computer_security", "conceptual_physics",
    "econometrics", "electrical_engineering", "elementary_mathematics",
    "formal_logic", "global_facts", "high_school_biology",
    "high_school_chemistry", "high_school_computer_science",
    "high_school_european_history", "high_school_geography",
    "high_school_government_and_politics", "high_school_macroeconomics",
    "high_school_mathematics", "high_school_microeconomics",
    "high_school_physics", "high_school_psychology", "high_school_statistics",
    "high_school_us_history", "high_school_world_history", "human_aging",
    "human_sexuality", "international_law", "jurisprudence",
    "logical_fallacies", "machine_learning", "management", "marketing",
    "medical_genetics", "miscellaneous", "moral_disputes",
    "moral_scenarios", "nutrition", "philosophy", "prehistory",
    "professional_accounting", "professional_law",
    "professional_medicine", "professional_psychology",
    "public_relations", "security_studies", "sociology",
    "us_foreign_policy", "virology", "world_religions",
]

# Subject -> MMLU category mapping (for per-category reporting)
SUBJECT_TO_CATEGORY = {}
_STEM = {
    "abstract_algebra", "anatomy", "astronomy", "college_biology",
    "college_chemistry", "college_computer_science", "college_mathematics",
    "college_medicine", "college_physics", "computer_security",
    "conceptual_physics", "electrical_engineering", "elementary_mathematics",
    "high_school_biology", "high_school_chemistry",
    "high_school_computer_science", "high_school_mathematics",
    "high_school_physics", "high_school_statistics", "machine_learning",
}
_HUMANITIES = {
    "formal_logic", "high_school_european_history", "high_school_us_history",
    "high_school_world_history", "international_law", "jurisprudence",
    "logical_fallacies", "moral_disputes", "moral_scenarios", "philosophy",
    "prehistory", "world_religions",
}
_SOCIAL_SCIENCES = {
    "econometrics", "high_school_geography",
    "high_school_government_and_politics", "high_school_macroeconomics",
    "high_school_microeconomics", "high_school_psychology",
    "professional_accounting",
    "professional_law", "professional_psychology", "public_relations",
    "security_studies", "sociology", "us_foreign_policy",
}
_OTHER = {
    "business_ethics", "clinical_knowledge", "global_facts", "human_aging",
    "human_sexuality", "management", "marketing", "medical_genetics",
    "miscellaneous", "nutrition", "professional_medicine", "virology",
}
for _s in _STEM:
    SUBJECT_TO_CATEGORY[_s] = "stem"
for _s in _HUMANITIES:
    SUBJECT_TO_CATEGORY[_s] = "humanities"
for _s in _SOCIAL_SCIENCES:
    SUBJECT_TO_CATEGORY[_s] = "social_sciences"
for _s in _OTHER:
    SUBJECT_TO_CATEGORY[_s] = "other"


# ── Dataset loading ─────────────────────────────────────────────────────────

def load_mmlu_redux(subjects: Optional[List[str]] = None) -> Dict[str, list]:
    """Load MMLU-Redux from HuggingFace, returning {subject: [rows]}."""
    from datasets import load_dataset

    if subjects is None:
        subjects = ALL_SUBJECTS

    data = {}
    total_subjects = len(subjects)
    for idx, subj in enumerate(subjects, start=1):
        print(f"Loading subject {idx}/{total_subjects}: {subj}")
        ds = load_dataset(
            "fxmarty/mmlu-redux-2.0-ok", name=subj, split="test",
        )
        data[subj] = list(ds)
    return data


# ── Few-shot example construction ───────────────────────────────────────────

def format_question(question: str, choices: List[str]) -> str:
    """Format a single MMLU question with A/B/C/D options."""
    letters = ["A", "B", "C", "D"]
    opts = "\n".join(f"{letters[i]}. {choices[i]}" for i in range(len(choices)))
    return f"{question.strip()}\n{opts}"


def build_fewshot_prefix(subject: str, subject_data: list, num_shots: int) -> str:
    """Build a few-shot prefix from the first `num_shots` examples of the subject.

    Uses the standard MMLU 5-shot protocol: examples are drawn from the subject's
    own data. Because MMLU-Redux only has a test split, we draw examples from the
    beginning of the test set and skip them during evaluation.
    """
    letters = ["A", "B", "C", "D"]
    nice_name = subject.replace("_", " ")
    prefix = (
        f"The following are multiple choice questions (with answers) "
        f"about {nice_name}.\n\n"
    )
    for i in range(min(num_shots, len(subject_data))):
        row = subject_data[i]
        q = format_question(row["question"], row["choices"])
        answer_letter = letters[row["answer"]]
        prefix += f"{q}\nAnswer: {answer_letter}\n\n"
    return prefix


def build_prompt_text(
    question: str,
    choices: List[str],
    fewshot_prefix: str,
) -> str:
    """Build the full prompt for one evaluation question."""
    q = format_question(question, choices)
    suffix = (
        "Please respond with the correct letter (A, B, C or D) "
        "without any additional comments, only the correct letter:"
    )
    return f"{fewshot_prefix}{q}\n{suffix}"


# ── Answer extraction ───────────────────────────────────────────────────────

_ANSWER_PATTERNS = [
    re.compile(r"(?i)(?:final answer|answer)\s*[:\-]?\s*\(?([ABCD])\)?\b"),
    re.compile(r"(?m)^\s*\(?([ABCD])\)?\s*$"),
]
_STANDALONE_LETTER_RE = re.compile(r"\b([ABCD])\b")


def extract_answer(text: str) -> Optional[str]:
    """Extract a final A/B/C/D answer, preferring text after any reasoning block."""
    text = text.strip()
    candidates = []
    if "</think>" in text:
        post_think = text.rsplit("</think>", 1)[-1].strip()
        if post_think:
            candidates.append(post_think)
    candidates.append(text)

    for candidate in candidates:
        for pattern in _ANSWER_PATTERNS:
            matches = pattern.findall(candidate)
            if matches:
                return matches[-1]
        standalone = _STANDALONE_LETTER_RE.findall(candidate)
        if standalone:
            return standalone[-1]
    return None


def build_eval_items(
    subjects: List[str],
    data: Dict[str, list],
    num_shots: int,
    max_eval_examples_per_subject: Optional[int],
) -> List[Dict[str, Any]]:
    """Build the ordered list of evaluation items."""
    letters = ["A", "B", "C", "D"]
    eval_items = []

    for subj in subjects:
        rows = data[subj]
        prefix = build_fewshot_prefix(subj, rows, num_shots)
        eval_start = min(num_shots, len(rows))
        eval_rows = rows[eval_start:]
        if max_eval_examples_per_subject is not None:
            eval_rows = eval_rows[:max_eval_examples_per_subject]

        for row in eval_rows:
            eval_items.append({
                "index": len(eval_items),
                "subject": subj,
                "question": row["question"],
                "correct_answer": letters[row["answer"]],
                "prompt": build_prompt_text(row["question"], row["choices"], prefix),
            })

    return eval_items


def build_per_question_record(
    item: Dict[str, Any],
    raw_response: str,
    save_responses: bool,
) -> Dict[str, Any]:
    """Create the saved record for a single evaluated question."""
    predicted_answer = extract_answer(raw_response)
    correct = predicted_answer is not None and predicted_answer.upper() == item["correct_answer"].upper()
    record = {
        "index": item["index"],
        "subject": item["subject"],
        "question": item["question"],
        "correct_answer": item["correct_answer"],
        "predicted_answer": predicted_answer,
        "correct": correct,
    }
    if save_responses:
        record["raw_response"] = raw_response
    return record


def summarize_per_question(
    per_question: List[Dict[str, Any]],
    subjects: List[str],
) -> Tuple[int, int, int, Dict[str, Dict[str, Any]], Dict[str, Dict[str, Any]]]:
    """Aggregate accuracy and parse stats from saved per-question results."""
    per_subject = defaultdict(lambda: {"correct": 0, "total": 0, "parse_failures": 0})
    category_agg = defaultdict(lambda: {"correct": 0, "total": 0})

    for record in per_question:
        subj = record["subject"]
        per_subject[subj]["total"] += 1
        if record["predicted_answer"] is None:
            per_subject[subj]["parse_failures"] += 1
        elif record["correct"]:
            per_subject[subj]["correct"] += 1

    subject_results = {}
    for subj in subjects:
        s = per_subject[subj]
        acc = s["correct"] / s["total"] if s["total"] > 0 else 0.0
        subject_results[subj] = {
            "accuracy": round(acc, 4),
            "correct": s["correct"],
            "total": s["total"],
            "parse_failures": s["parse_failures"],
        }
        cat = SUBJECT_TO_CATEGORY.get(subj, "other")
        category_agg[cat]["correct"] += s["correct"]
        category_agg[cat]["total"] += s["total"]

    category_results = {}
    for cat in ["stem", "humanities", "social_sciences", "other"]:
        a = category_agg[cat]
        acc = a["correct"] / a["total"] if a["total"] > 0 else 0.0
        category_results[cat] = {
            "accuracy": round(acc, 4),
            "correct": a["correct"],
            "total": a["total"],
        }

    total_correct = sum(s["correct"] for s in per_subject.values())
    processed_questions = len(per_question)
    total_parse_failures = sum(s["parse_failures"] for s in per_subject.values())
    return (
        total_correct,
        processed_questions,
        total_parse_failures,
        category_results,
        subject_results,
    )


def build_results_payload(
    config: Dict[str, Any],
    per_question: List[Dict[str, Any]],
    elapsed_seconds: float,
) -> Dict[str, Any]:
    """Build the saved JSON payload for either a partial or complete run."""
    subjects = config["subjects"]
    total_correct, processed_questions, total_parse_failures, category_results, subject_results = summarize_per_question(
        per_question, subjects
    )
    overall_accuracy = total_correct / processed_questions if processed_questions > 0 else 0.0
    expected_total_questions = config["expected_total_questions"]

    return {
        "config": config,
        "summary": {
            "overall_accuracy": round(overall_accuracy, 4),
            "total_correct": total_correct,
            "processed_questions": processed_questions,
            "total_questions": expected_total_questions,
            "total_parse_failures": total_parse_failures,
            "elapsed_seconds": round(elapsed_seconds, 1),
            "is_complete": processed_questions == expected_total_questions,
        },
        "category_results": category_results,
        "subject_results": subject_results,
        "timestamp": datetime.now().isoformat(),
        "per_question": per_question,
    }


def write_results_atomic(output_path: str, payload: Dict[str, Any]) -> None:
    """Write the results JSON atomically to avoid corrupt partial files."""
    output = Path(output_path)
    output.parent.mkdir(parents=True, exist_ok=True)
    tmp_path = output.with_suffix(output.suffix + ".tmp")
    tmp_path.write_text(json.dumps(payload, indent=2))
    tmp_path.replace(output)


def validate_resume_config(existing: Dict[str, Any], current: Dict[str, Any]) -> None:
    """Fail fast if a resume attempt changes the semantic evaluation protocol."""
    keys_to_match = [
        "model_path",
        "base_model",
        "backend",
        "num_shots",
        "max_new_tokens",
        "disable_thinking",
        "temperature",
        "top_p",
        "top_k",
        "min_p",
        "seed",
        "dtype",
        "subjects",
        "max_eval_examples_per_subject",
        "dataset",
        "protocol",
    ]
    for key in keys_to_match:
        if existing.get(key) != current.get(key):
            raise ValueError(
                f"Resume config mismatch for '{key}': existing={existing.get(key)!r}, current={current.get(key)!r}"
            )


# ── Steering vector support ─────────────────────────────────────────────────

if "ResidualSteeringHook" not in dir():
    class ResidualSteeringHook:
        """Minimal residual-stream steering hook (standalone fallback)."""

        def __init__(self, direction: torch.Tensor, alpha: float,
                     apply_mode: str = "last_prompt_and_current",
                     prompt_last_indices: Optional[List[int]] = None):
            self.direction = direction
            self.alpha = float(alpha)
            self.apply_mode = apply_mode
            self._handle = None

        def _broadcast(self, hidden: torch.Tensor) -> torch.Tensor:
            d = self.direction.to(device=hidden.device, dtype=hidden.dtype)
            while d.dim() < hidden.dim():
                d = d.unsqueeze(0)
            return d

        def __call__(self, module, args, output):
            hidden = output[0] if isinstance(output, tuple) else output
            d = self._broadcast(hidden)
            if self.apply_mode == "all_positions":
                steered = hidden + self.alpha * d
            else:
                steered = hidden.clone()
                steered[:, -1, :] = steered[:, -1, :] + self.alpha * d
            if isinstance(output, tuple):
                return (steered, *output[1:])
            return steered

        def register(self, model, layer_index: int):
            layers = _get_model_layers(model)
            self._handle = layers[layer_index].register_forward_hook(self, with_kwargs=False)

        def remove(self):
            if self._handle is not None:
                self._handle.remove()
                self._handle = None


if "load_steering_direction" not in dir():
    def load_steering_direction(path: str) -> torch.Tensor:
        """Load a steering vector from disk."""
        obj = torch.load(path, map_location="cpu", weights_only=False)
        if isinstance(obj, torch.Tensor):
            return obj
        if isinstance(obj, (list, tuple)):
            return torch.tensor(obj)
        if isinstance(obj, dict):
            for key in ("direction", "icv_direction", "vector", "steering_direction"):
                if key in obj:
                    v = obj[key]
                    return torch.tensor(v) if not isinstance(v, torch.Tensor) else v
        raise ValueError(f"Cannot parse steering direction from {path}")


def _get_model_layers(model):
    """Return the list of transformer layers for hook registration."""
    if hasattr(model, "model") and hasattr(model.model, "layers"):
        return model.model.layers  # Qwen, Llama, Mistral
    if hasattr(model, "transformer") and hasattr(model.transformer, "h"):
        return model.transformer.h  # GPT-2 style
    raise ValueError("Cannot find transformer layers for steering hook registration.")


# ── Model loading helpers ───────────────────────────────────────────────────

def load_model_transformers(
    model_path: str,
    base_model: Optional[str],
    disable_thinking: bool,
    dtype: str,
) -> Tuple[Any, Any]:
    """Load model and tokenizer via transformers (+ optional PEFT adapter)."""
    from transformers import AutoModelForCausalLM, AutoTokenizer

    torch_dtype = {"float16": torch.float16, "bfloat16": torch.bfloat16,
                   "float32": torch.float32, "auto": "auto"}[dtype]

    if base_model and model_path != base_model:
        # Load base + adapter
        from peft import PeftModel
        print(f"Loading base model: {base_model}")
        model = AutoModelForCausalLM.from_pretrained(
            base_model, torch_dtype=torch_dtype, device_map="auto",
            trust_remote_code=True,
        )
        print(f"Loading adapter: {model_path}")
        model = PeftModel.from_pretrained(model, model_path)
        model = model.merge_and_unload()
        tokenizer = AutoTokenizer.from_pretrained(base_model, trust_remote_code=True)
    else:
        print(f"Loading model: {model_path}")
        model = AutoModelForCausalLM.from_pretrained(
            model_path, torch_dtype=torch_dtype, device_map="auto",
            trust_remote_code=True,
        )
        tokenizer = AutoTokenizer.from_pretrained(model_path, trust_remote_code=True)

    model.eval()
    if tokenizer.pad_token is None:
        tokenizer.pad_token = tokenizer.eos_token
    return model, tokenizer


def generate_transformers(
    model: Any,
    tokenizer: Any,
    prompts: List[str],
    max_new_tokens: int,
    disable_thinking: bool,
    temperature: float,
    top_p: float,
    top_k: int,
    min_p: float,
    batch_size: int,
    steering_hook: Optional["ResidualSteeringHook"] = None,
    steering_layer: Optional[int] = None,
) -> List[str]:
    """Generate responses for prompts using transformers in repeated mini-batches."""
    # Register steering hook if provided
    if steering_hook is not None and steering_layer is not None:
        steering_hook.register(model, steering_layer)

    do_sample = temperature > 0
    results = []
    try:
        for start in range(0, len(prompts), batch_size):
            batch_prompts = prompts[start:start + batch_size]
            formatted = []
            for prompt in batch_prompts:
                messages = [{"role": "user", "content": prompt}]
                chat_kwargs = {}
                if disable_thinking:
                    chat_kwargs["enable_thinking"] = False
                formatted.append(
                    tokenizer.apply_chat_template(
                        messages, tokenize=False, add_generation_prompt=True, **chat_kwargs,
                    )
                )

            inputs = tokenizer(formatted, return_tensors="pt", padding=True).to(model.device)
            generate_kwargs = {
                "max_new_tokens": max_new_tokens,
                "do_sample": do_sample,
            }
            if do_sample:
                generate_kwargs.update(
                    temperature=temperature,
                    top_p=top_p,
                    top_k=top_k,
                    min_p=min_p,
                )
            else:
                generate_kwargs.update(
                    temperature=None,
                    top_p=None,
                    top_k=None,
                )
            with torch.no_grad():
                output_ids = model.generate(**inputs, **generate_kwargs)

            # `generate()` returns the full padded input plus newly generated
            # tokens. For batched decoder-only models, slice from the shared
            # padded input width, not from each row's non-pad token count.
            # Otherwise left-padded batches can leak prompt text (including
            # chat-template role markers) into the decoded "response".
            padded_input_len = inputs["input_ids"].shape[1]
            for row_idx in range(output_ids.shape[0]):
                new_tokens = output_ids[row_idx, padded_input_len:]
                response = tokenizer.decode(new_tokens, skip_special_tokens=True)
                results.append(response)
    finally:
        if steering_hook is not None:
            steering_hook.remove()

    return results


def load_vllm(
    model_path: str,
    base_model: Optional[str],
    dtype: str,
    gpu_memory_utilization: float,
) -> Tuple[Any, Any]:
    """Load a vLLM model and tokenizer once for repeated generation."""
    from vllm import LLM

    load_path = model_path
    vllm_kwargs = {}

    # For PEFT adapters, we'd need to merge first or use vllm's LoRA support.
    # For simplicity, assume model_path is a merged model or a HF model ID.
    if base_model and model_path != base_model:
        print(
            "WARNING: vLLM backend with separate adapter path requires a "
            "pre-merged model. Attempting to load model_path directly. "
            "If this fails, merge the adapter first or use --backend transformers."
        )

    print(f"Loading vLLM model: {load_path}")
    llm = LLM(
        model=load_path,
        dtype=dtype,
        trust_remote_code=True,
        gpu_memory_utilization=gpu_memory_utilization,
        max_model_len=4096,
        enable_prefix_caching=True,
        **vllm_kwargs,
    )
    tokenizer = llm.get_tokenizer()
    return llm, tokenizer


def generate_vllm_batch(
    llm: Any,
    tokenizer: Any,
    prompts_with_chat: List[str],
    max_new_tokens: int,
    disable_thinking: bool,
    temperature: float,
    top_p: float,
    top_k: int,
    min_p: float,
    seed: int,
) -> List[str]:
    """Generate one batch of responses using an already loaded vLLM model."""
    from vllm import SamplingParams

    sampling_params = SamplingParams(
        temperature=temperature,
        top_p=top_p,
        top_k=top_k,
        min_p=min_p,
        seed=seed,
        max_tokens=max_new_tokens,
        stop=["</s>"],
    )

    formatted = []
    for prompt in prompts_with_chat:
        messages = [{"role": "user", "content": prompt}]
        chat_kwargs = {}
        if disable_thinking:
            chat_kwargs["enable_thinking"] = False
        text = tokenizer.apply_chat_template(
            messages, tokenize=False, add_generation_prompt=True, **chat_kwargs,
        )
        formatted.append(text)

    outputs = llm.generate(formatted, sampling_params, use_tqdm=False)
    return [o.outputs[0].text for o in outputs]


# ── Main evaluation loop ────────────────────────────────────────────────────

def evaluate(
    model_path: str,
    base_model: Optional[str],
    backend: str,
    subjects: Optional[List[str]],
    num_shots: int,
    max_new_tokens: int,
    disable_thinking: bool,
    temperature: float,
    top_p: float,
    top_k: int,
    min_p: float,
    seed: int,
    dtype: str,
    output_path: str,
    gpu_memory_utilization: float,
    save_responses: bool,
    max_eval_examples_per_subject: Optional[int] = None,
    batch_size: int = 64,
    save_every_batches: int = 1,
    resume: bool = False,
    checkpoint_callback: Optional[Callable[[str, Dict[str, Any]], None]] = None,
    steering_direction_path: Optional[str] = None,
    steering_layer: Optional[int] = None,
    steering_alpha: float = 0.0,
    steering_apply_mode: str = "last_prompt_and_current",
) -> Dict[str, Any]:
    """Run the full MMLU-Redux evaluation."""

    subjects = subjects or ALL_SUBJECTS
    print(f"Loading MMLU-Redux data for {len(subjects)} subjects...")
    data = load_mmlu_redux(subjects)
    eval_items = build_eval_items(subjects, data, num_shots, max_eval_examples_per_subject)
    expected_total_questions = len(eval_items)
    print(f"Total evaluation questions: {expected_total_questions}")

    config = {
        "model_path": model_path,
        "base_model": base_model,
        "backend": backend,
        "num_shots": num_shots,
        "max_new_tokens": max_new_tokens,
        "disable_thinking": disable_thinking,
        "temperature": temperature,
        "top_p": top_p,
        "top_k": top_k,
        "min_p": min_p,
        "seed": seed,
        "dtype": dtype,
        "num_subjects": len(subjects),
        "subjects": subjects,
        "max_eval_examples_per_subject": max_eval_examples_per_subject,
        "batch_size": batch_size,
        "save_every_batches": save_every_batches,
        "gpu_memory_utilization": gpu_memory_utilization,
        "save_responses": save_responses,
        "dataset": "fxmarty/mmlu-redux-2.0-ok",
        "protocol": "Qwen3 tech report: 5-shot generative exact-match",
        "expected_total_questions": expected_total_questions,
        "steering_direction_path": steering_direction_path,
        "steering_layer": steering_layer,
        "steering_alpha": steering_alpha,
        "steering_apply_mode": steering_apply_mode,
    }

    output = Path(output_path)
    per_question: List[Dict[str, Any]] = []
    previous_elapsed_seconds = 0.0
    if output.exists():
        if not resume:
            raise FileExistsError(
                f"Output already exists: {output_path}. Pass --resume to continue from this checkpoint."
            )
        existing_payload = json.loads(output.read_text())
        validate_resume_config(existing_payload["config"], config)
        per_question = existing_payload.get("per_question", [])
        previous_elapsed_seconds = float(existing_payload.get("summary", {}).get("elapsed_seconds", 0.0))
        print(f"Resuming from {len(per_question)} completed questions in {output_path}")
        if len(per_question) >= expected_total_questions:
            print("Run is already complete; returning saved results.")
            return existing_payload
    elif resume:
        print(f"No existing output at {output_path}; starting a fresh run.")

    # Prepare steering hook if requested
    steering_hook = None
    if steering_direction_path and steering_layer is not None:
        if backend == "vllm":
            print("WARNING: Steering vectors are only supported with the transformers "
                  "backend. Ignoring steering direction for vLLM.")
        else:
            direction = load_steering_direction(steering_direction_path)
            steering_hook = ResidualSteeringHook(
                direction=direction, alpha=steering_alpha,
                apply_mode=steering_apply_mode,
            )
            print(f"Steering: layer={steering_layer}, alpha={steering_alpha}, "
                  f"mode={steering_apply_mode}")

    random.seed(seed)
    if backend != "vllm":
        torch.manual_seed(seed)
        if torch.cuda.is_available():
            torch.cuda.manual_seed_all(seed)

    # Generate in batches so long runs can checkpoint and resume.
    t0 = time.time()
    if backend == "vllm":
        llm, tokenizer = load_vllm(
            model_path=model_path,
            base_model=base_model,
            dtype=dtype,
            gpu_memory_utilization=gpu_memory_utilization,
        )
    else:
        model, tokenizer = load_model_transformers(
            model_path, base_model, disable_thinking, dtype,
        )
    processed_before = len(per_question)
    if processed_before >= expected_total_questions:
        elapsed = previous_elapsed_seconds
    else:
        for batch_num, start in enumerate(range(processed_before, expected_total_questions, batch_size), start=1):
            batch_items = eval_items[start:start + batch_size]
            batch_prompts = [item["prompt"] for item in batch_items]

            if backend == "vllm":
                responses = generate_vllm_batch(
                    llm=llm,
                    tokenizer=tokenizer,
                    prompts_with_chat=batch_prompts,
                    max_new_tokens=max_new_tokens,
                    disable_thinking=disable_thinking,
                    temperature=temperature,
                    top_p=top_p,
                    top_k=top_k,
                    min_p=min_p,
                    seed=seed + start,
                )
            else:
                responses = generate_transformers(
                    model=model,
                    tokenizer=tokenizer,
                    prompts=batch_prompts,
                    max_new_tokens=max_new_tokens,
                    disable_thinking=disable_thinking,
                    temperature=temperature,
                    top_p=top_p,
                    top_k=top_k,
                    min_p=min_p,
                    batch_size=len(batch_prompts),
                    steering_hook=steering_hook,
                    steering_layer=steering_layer,
                )

            for item, response in zip(batch_items, responses):
                per_question.append(build_per_question_record(item, response, save_responses))

            processed_now = len(per_question)
            elapsed_so_far = previous_elapsed_seconds + (time.time() - t0)
            print(
                f"Processed {processed_now}/{expected_total_questions} questions "
                f"({processed_now - processed_before} this run)"
            )

            if batch_num % save_every_batches == 0 or processed_now == expected_total_questions:
                results = build_results_payload(config, per_question, elapsed_so_far)
                write_results_atomic(output_path, results)
                if checkpoint_callback is not None:
                    checkpoint_callback(output_path, results)
                print(f"Checkpoint saved to {output_path}")

        elapsed = previous_elapsed_seconds + (time.time() - t0)

    results = build_results_payload(config, per_question, elapsed)
    write_results_atomic(output_path, results)
    if checkpoint_callback is not None:
        checkpoint_callback(output_path, results)
    print(f"\nResults saved to {output_path}")

    # Print summary
    print(f"\n{'=' * 60}")
    print(f"MMLU-Redux Results ({num_shots}-shot, generative)")
    print(f"Model: {model_path}")
    print(f"{'=' * 60}")
    print(
        f"Overall accuracy: {results['summary']['overall_accuracy']:.1%} "
        f"({results['summary']['total_correct']}/{results['summary']['processed_questions']})"
    )
    print(f"Parse failures: {results['summary']['total_parse_failures']}")
    print(f"\nPer-category:")
    for cat in ["stem", "humanities", "social_sciences", "other"]:
        c = results["category_results"].get(cat, {})
        print(f"  {cat:20s}: {c.get('accuracy', 0):.1%} ({c.get('correct', 0)}/{c.get('total', 0)})")
    print(f"\nPer-subject (sorted by accuracy):")
    sorted_subjs = sorted(results["subject_results"].items(), key=lambda x: x[1]["accuracy"])
    for subj, r in sorted_subjs:
        print(f"  {subj:40s}: {r['accuracy']:.1%} ({r['correct']}/{r['total']})")

    return results


# ── CLI ─────────────────────────────────────────────────────────────────────

def main():
    parser = argparse.ArgumentParser(
        description="Evaluate a model on MMLU-Redux (Qwen3 tech report protocol: 5-shot generative)",
        formatter_class=argparse.RawDescriptionHelpFormatter,
    )
    parser.add_argument(
        "--model_path", required=True,
        help="HuggingFace model ID or local path (model or adapter)",
    )
    parser.add_argument(
        "--base_model", default=None,
        help="Base model ID when model_path is a PEFT adapter",
    )
    parser.add_argument(
        "--backend", choices=["transformers", "vllm"], default="transformers",
        help="Inference backend (default: transformers)",
    )
    parser.add_argument(
        "--subjects", nargs="+", default=None,
        help="Specific subjects to evaluate (default: all 57)",
    )
    parser.add_argument(
        "--num_shots", type=int, default=5,
        help="Number of few-shot examples (default: 5, matching Qwen3 report)",
    )
    parser.add_argument(
        "--max_new_tokens", type=int, default=32,
        help="Max tokens to generate per question (default: 32; only a letter is needed)",
    )
    parser.add_argument(
        "--temperature", type=float, default=0.0,
        help="Sampling temperature (default: 0.0 for deterministic decoding)",
    )
    parser.add_argument(
        "--top_p", type=float, default=1.0,
        help="Top-p nucleus sampling threshold (default: 1.0)",
    )
    parser.add_argument(
        "--top_k", type=int, default=-1,
        help="Top-k sampling cutoff (default: -1, disabled)",
    )
    parser.add_argument(
        "--min_p", type=float, default=0.0,
        help="Minimum token probability cutoff (default: 0.0)",
    )
    parser.add_argument(
        "--seed", type=int, default=12345,
        help="Random seed for sampled decoding (default: 12345)",
    )
    parser.add_argument(
        "--disable_thinking", action="store_true",
        help="Disable thinking/CoT mode for Qwen3 models",
    )
    parser.add_argument(
        "--dtype", default="bfloat16",
        choices=["float16", "bfloat16", "float32", "auto"],
        help="Model dtype (default: bfloat16)",
    )
    parser.add_argument(
        "--output", default=None,
        help="Output JSON path (default: mmlu_redux_results_<model>_<timestamp>.json)",
    )
    parser.add_argument(
        "--gpu_memory_utilization", type=float, default=0.9,
        help="GPU memory utilization for vLLM (default: 0.9)",
    )
    parser.add_argument(
        "--no_save_responses", action="store_true",
        help="Don't save per-question responses (saves disk space)",
    )
    parser.add_argument(
        "--max_eval_examples_per_subject", type=int, default=None,
        help="Optional cap on scored examples per subject after the few-shot prefix",
    )
    parser.add_argument(
        "--batch_size", type=int, default=None,
        help="Generation batch size (default: 64 for vLLM, 8 for transformers)",
    )
    parser.add_argument(
        "--save_every_batches", type=int, default=1,
        help="Write a JSON checkpoint every N generation batches (default: 1)",
    )
    parser.add_argument(
        "--resume", action="store_true",
        help="Resume from an existing output JSON with the same eval configuration",
    )

    # Steering vector options (transformers backend only).
    parser.add_argument(
        "--steering_direction_path", type=str, default=None,
        help="Path to a precomputed steering vector (.pt tensor or dict wrapper)",
    )
    parser.add_argument(
        "--steering_layer", type=int, default=None,
        help="Transformer block index (0-based) for steering injection",
    )
    parser.add_argument(
        "--alphas", type=str, default="0.0",
        help='Comma-separated steering strengths to sweep (e.g. "0,0.5,1.0,2.0")',
    )
    parser.add_argument(
        "--steering_apply_mode",
        choices=["last_prompt_and_current", "all_positions"],
        default="last_prompt_and_current",
        help="How to apply the steering vector (default: last_prompt_and_current)",
    )

    args = parser.parse_args()

    if args.batch_size is None:
        args.batch_size = 64 if args.backend == "vllm" else 8
    if args.batch_size < 1:
        raise ValueError("--batch_size must be >= 1")
    if args.save_every_batches < 1:
        raise ValueError("--save_every_batches must be >= 1")

    alphas = [float(a.strip()) for a in args.alphas.split(",") if a.strip()]
    if not alphas:
        alphas = [0.0]

    for alpha in alphas:
        if args.output is not None and len(alphas) == 1:
            output_path = args.output
        else:
            model_short = args.model_path.replace("/", "_").replace("\\", "_")
            ts = datetime.now().strftime("%Y%m%d_%H%M%S")
            alpha_tag = f"_alpha{alpha}" if alpha != 0.0 else ""
            output_path = f"mmlu_redux_results_{model_short}{alpha_tag}_{ts}.json"

        if len(alphas) > 1:
            print(f"\n{'#' * 60}")
            print(f"# Steering alpha = {alpha}")
            print(f"{'#' * 60}")

        evaluate(
            model_path=args.model_path,
            base_model=args.base_model,
            backend=args.backend,
            subjects=args.subjects,
            num_shots=args.num_shots,
            max_new_tokens=args.max_new_tokens,
            disable_thinking=args.disable_thinking,
            temperature=args.temperature,
            top_p=args.top_p,
            top_k=args.top_k,
            min_p=args.min_p,
            seed=args.seed,
            dtype=args.dtype,
            output_path=output_path,
            gpu_memory_utilization=args.gpu_memory_utilization,
            save_responses=not args.no_save_responses,
            max_eval_examples_per_subject=args.max_eval_examples_per_subject,
            batch_size=args.batch_size,
            save_every_batches=args.save_every_batches,
            resume=args.resume,
            steering_direction_path=args.steering_direction_path,
            steering_layer=args.steering_layer,
            steering_alpha=alpha,
            steering_apply_mode=args.steering_apply_mode,
        )


if __name__ == "__main__":
    main()
