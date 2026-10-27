# Multi-View Attention Multiple-Instance Learning Enhanced by LLM Reasoning for Cognitive Distortion Detection

The dataset used in the paper: *"Multi-View Attention Multiple-Instance Learning Enhanced by LLM Reasoning for Cognitive Distortion Detection"* (ACL 2026 Main)

[![Paper](https://img.shields.io/badge/Paper-arXiv%202509.17292-red.svg)](https://arxiv.org/abs/2509.17292)
[![KoACD](https://img.shields.io/badge/🤗%20KoACD-HuggingFace-blue.svg)](https://huggingface.co/datasets/kma80kjs1/KoACD)
[![License](https://img.shields.io/badge/License-CC_BY--NC_4.0-green.svg)](https://creativecommons.org/licenses/by-nc/4.0/)

---

## Overview

This repository contains the datasets and implementation details for the MVACD framework, which combines Large Language Models (LLMs) with a Multiple-Instance Learning (MIL) architecture for cognitive distortion detection.

Each utterance is decomposed into **Emotion, Logic, and Behavior (ELB)** components, processed by LLMs to infer multiple distortion instances with predicted types, expressions, and salience scores. These are integrated via a **Multi-View Gated Attention** mechanism for final classification.

---

## ELB Extraction

The zero-shot ELB extraction prompt from Appendix F of the paper is included at
[`Prompts/elb_extraction.txt`](Prompts/elb_extraction.txt). The `{sentence}`
placeholder is replaced by `Code/extract_elb.py` for each input utterance.

The extraction script currently expects an Excel workbook containing a
`Generated Story` column:

```bash
python Code/extract_elb.py \
  --input path/to/input.xlsx \
  --prompt Prompts/elb_extraction.txt \
  --output path/to/output_with_elb.xlsx
```

Set `OPENAI_API_KEY` in the environment or a local `.env` file before running
the command. The included `Data.csv` uses the column name `Related Sentence`,
so it must be converted or the script must be adapted before it can be used
directly as extraction input.

---

## Therapist QA Reproduction with NVIDIA NIM

Therapist QA is the smaller dataset evaluated in the paper. The labeled source
contains 2,530 patient questions. Following the paper, preprocessing removes
the 933 `No Distortion` examples and retains the primary (`Dominant
Distortion`) label, producing exactly 1,597 examples across 10 classes.

The reproduction uses the paper's core algorithm and hyperparameters but
replaces its three proprietary inference models with three NVIDIA-hosted models
of increasing total parameter count:

| Role | NVIDIA model ID | Approximate size |
|---|---|---:|
| Small | `openai/gpt-oss-20b` | 21B total / 3.6B active |
| Medium | `google/gemma-4-31b-it` | 33B |
| Large | `nvidia/nemotron-3-super-120b-a12b` | 124B total / 12B active |

All three use NVIDIA's OpenAI-compatible endpoint. The ELB extraction stage
uses GPT-OSS 20B; all three models independently generate the MIL instances.
Model IDs can be overridden from the command line.

> **Data handling:** Therapist QA contains sensitive mental-health narratives.
> NVIDIA states that inputs and outputs sent to its prototype API may be logged.
> Review the current NVIDIA API terms and your research ethics requirements
> before submitting the full dataset. Use self-hosted NIM endpoints if external
> processing is not permitted.

### Setup

```bash
python -m venv .venv
source .venv/bin/activate
pip install -r requirements_MVACD.txt
```

Set `NVIDIA_API_KEY` in `.env`, export it in the shell, or pass the existing
environment file explicitly with `--env-file`. API keys are never copied into
the repository.

### 1. Prepare the paper dataset

The command downloads the labeled public Kaggle release and verifies the exact
class distribution reported by the paper:

```bash
python Code/prepare_therapist_qa.py \
  --output Data/therapist_qa.csv
```

For an offline run, download the dataset ZIP separately and pass it through
`--input path/to/cognitive-distortion-dataset.zip`.

### 2. Extract ELB components

Start with `--limit 1` as an inexpensive API smoke test. Remove it for all
1,597 examples. Output is append-only JSONL, so interrupted runs resume without
repeating completed examples.

NVIDIA's free prototype endpoints can queue requests for several minutes. Both
generation commands therefore default to a 600-second request timeout, which
can be changed with `--timeout`.

```bash
python Code/extract_elb_nvidia.py \
  --input Data/therapist_qa.csv \
  --output Artifacts/therapist_qa_elb.jsonl \
  --env-file ../llm-detoxification/.env \
  --limit 1
```

### 3. Infer instances with all three models

```bash
python Code/infer_instances_nvidia.py \
  --input Artifacts/therapist_qa_elb.jsonl \
  --output Artifacts/therapist_qa_instances_elb.jsonl \
  --env-file ../llm-detoxification/.env \
  --limit 1
```

For the paper's no-ELB comparison, run the same inputs with `--without-elb`:

```bash
python Code/infer_instances_nvidia.py \
  --input Artifacts/therapist_qa_elb.jsonl \
  --output Artifacts/therapist_qa_instances_no_elb.jsonl \
  --env-file ../llm-detoxification/.env \
  --without-elb \
  --limit 1
```

### 4. Build MiniLM tensors

The paper embeds the original utterance and each `type: relevant_text`
instance with `sentence-transformers/all-MiniLM-L12-v2`. Bags are zero-padded,
and padded salience values are zero.

```bash
python Code/build_embeddings.py \
  --input Artifacts/therapist_qa_instances_elb.jsonl \
  --output Artifacts/therapist_qa_elb.npz

python Code/build_embeddings.py \
  --input Artifacts/therapist_qa_instances_no_elb.jsonl \
  --output Artifacts/therapist_qa_no_elb.npz
```

### 5. Train the paper's MIL architecture

Use one run and ten epochs to validate the workflow, then remove those two
overrides for the paper settings of ten runs and up to 100 epochs:

```bash
python Code/train.py \
  --elb Artifacts/therapist_qa_elb.npz \
  --no_elb Artifacts/therapist_qa_no_elb.npz \
  --instance_start_idx 1 \
  --num_runs 1 \
  --epochs 10 \
  --experiment_seed 42 \
  --output_dir Results/smoke
```

Replacing the three LLMs makes this a controlled reproduction of the method,
not an exact reproduction of the paper's reported scores. Full generation makes
approximately 6,388 API calls: 1,597 for ELB and 4,791 for three-model instance
inference, excluding retries.

---

## Datasets

### KoACD (Korean Adolescent Cognitive Distortion Dataset)

- **Source:** [Kim and Kim, 2025](https://arxiv.org/abs/2505.00367) — EMNLP Findings 2025
- **Subset used in this paper:** 5,000 utterances (500 per distortion type), expert-validated by 10 Korean psychologists

> ⚠️ **Note:** There is no fixed train/validation/test split. Each experimental run uses a different random seed for stratified splitting (80/10/10).

| Cognitive Distortion Type | Count (%) |
|---------------------------|-----------|
| Labeling | 478 (10.6%) |
| Mental Filtering | 470 (10.4%) |
| All-or-Nothing Thinking | 464 (10.3%) |
| Emotional Reasoning | 458 (10.2%) |
| Personalization | 459 (10.2%) |
| Overgeneralization | 452 (10.0%) |
| Discounting the Positive | 451 (10.0%) |
| Jumping to Conclusions | 431 (9.6%) |
| Magnification and Minimization | 432 (9.6%) |
| Should Statements | 415 (9.2%) |
| **Total** | **4,510 (100%)** |

### Therapist QA Dataset

- **Source:** [Shreevastava and Foltz, 2021](https://aclanthology.org/2021.clpsych-1.17/)
- **Usage:** Primary label per utterance; used for cross-linguistic generalization benchmarking

> ⚠️ **Note:** There is no fixed train/validation/test split. Each experimental run uses a different random seed for stratified splitting (80/10/10).

| Split | Utterances |
|-------|-----------|
| Train | 1,277 (80%) |
| Validation | 159 (10%) |
| Test | 161 (10%) |
| **Total** | **1,597** |

---

## Results

### Input Configuration Comparison (Weighted F1)

| Configuration | KoACD Val | KoACD Test | Therapist QA Val | Therapist QA Test |
|--------------|-----------|------------|-----------------|-------------------|
| Baseline | 0.504 ± 0.019 | 0.473 ± 0.015 | 0.410 ± 0.038 | 0.340 ± 0.037 |
| ELB only | 0.519 ± 0.016 | 0.483 ± 0.017 | 0.438 ± 0.028 | 0.378 ± 0.036 |
| Salience only | 0.518 ± 0.015 | 0.486 ± 0.014 | 0.428 ± 0.036 | 0.360 ± 0.035 |
| **ELB + Salience** | **0.529 ± 0.018** | **0.505 ± 0.014** | **0.460 ± 0.029** | **0.394 ± 0.034** |

### LLM Baseline Comparison (F1)

| Model | KoACD | Therapist QA |
|-------|-------|--------------|
| Gemini 2.0 Flash | 0.386 | 0.348 |
| GPT-4o | 0.325 | 0.332 |
| Claude 3.7 Sonnet | 0.272 | 0.318 |

---

## Citation

If you use this work, please cite:

```bibtex
@article{kim2025mvacd,
  title   = {Multi-View Attention Multiple-Instance Learning Enhanced by LLM Reasoning for Cognitive Distortion Detection},
  author  = {Kim, Jun Seo and Kim, Hyemi and Oh, Woo Joo and Cho, Hongjin and Lee, Hochul and Kim, Hye Hyeon},
  journal = {arXiv preprint arXiv:2509.17292},
  year    = {2025},
  url     = {https://arxiv.org/abs/2509.17292}
}
```

If you use the KoACD dataset, please also cite:

```bibtex
@inproceedings{kim2025koacd,
  title     = {KoACD: The First Korean Adolescent Dataset for Cognitive Distortion Analysis via Role-Switching Multi-LLM Negotiation},
  author    = {Kim, Jun Seo and Kim, Hye Hyeon},
  booktitle = {Findings of the Association for Computational Linguistics: EMNLP 2025},
  pages     = {22050--22078},
  year      = {2025},
  url       = {https://arxiv.org/abs/2505.00367}
}
```

---

## Contact

- **Jun Seo Kim** — [kma80kjs@gachon.ac.kr](mailto:kma80kjs@gachon.ac.kr)
- **Hye Hyeon Kim** — [hye_hyeon@yonsei.ac.kr](mailto:hye_hyeon@yonsei.ac.kr)

---

## License

This repository is licensed under [CC BY-NC 4.0](https://creativecommons.org/licenses/by-nc/4.0/) and is available for **research purposes only**.
