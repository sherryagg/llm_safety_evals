
# LLM Safety Evaluation Framework

Systematic evaluation of AI safety alignment using Anthropic's HH-RLHF dataset, comparing rule-based classification against LLM-as-judge (Claude 3 Sonnet) approaches.

## Overview

This project investigates how well simple keyword-based rules detect unsafe content compared to contextual LLM evaluation. Using 100 examples from the [Anthropic HH-RLHF harmless-base dataset](https://huggingface.co/datasets/Anthropic/hh-rlhf), we:

1. **Parse multi-turn conversations** — extracting context, final prompts, and chosen/rejected responses
2. **Apply rule-based classification** — keyword matching for harmful intent and refusal detection
3. **Deploy Claude-as-judge** — LLM evaluation scoring helpfulness, harmlessness, and refusal correctness
4. **Compare with and without context** — measuring how conversation history changes safety classifications

## Key Findings

| Metric | Result |
|--------|--------|
| Rule-based classification error rate | **87.5%** (missed 77/88 unsafe prompts) |
| Context changed classification | **18%** of examples shifted category |
| Severe safety violations found | **7** examples auto-flagged |
| Multi-turn conversation rate | **100%** — single-turn eval fundamentally incomplete |

### Results Comparison: Run 1 (No Context) vs Run 2 (Full Context)

| Category | Run 1 | Run 2 | Change |
|----------|-------|-------|--------|
| unsafe | 67 | 74 | +7 |
| unsafe\|unsafe_bias | 12 | 10 | -2 |
| unsafe_severe | 0 | 7 | +7 |
| ambiguous | 9 | 1 | -8 |
| safe | 8 | 5 | -3 |
| context_dependent | 4 | 2 | -2 |
| unsafe_bias | 0 | 1 | +1 |

## Visualisations

![Rule vs Claude Comparison](results/rule_vs_claude_comparison.png)

![Run 1 vs Run 2 Context Impact](results/run1_vs_run2_comparison.png)

**Takeaway:** Providing conversation context resolves ambiguity — most "ambiguous" and "context_dependent" cases resolved to "unsafe" when the full conversation was visible.

## Methodology

```
HH-RLHF Dataset (100 samples)
        │
        ▼
┌─────────────────┐
│ Parse Multi-Turn │
│ Conversations    │
└────────┬────────┘
         │
    ┌────┴────┐
    ▼         ▼
┌────────┐ ┌──────────────┐
│ Rule   │ │ Claude Judge │
│ Based  │ │ (Bedrock)    │
└───┬────┘ └──────┬───────┘
    │              │
    ▼              ▼
┌─────────────────────────┐
│ Compare Classifications │
│ + Score Analysis        │
└─────────────────────────┘
```

## Tech Stack

- **Python 3.9**
- **AWS Bedrock** — Claude 3 Sonnet model access
- **Claude 3 Sonnet** (`anthropic.claude-3-sonnet-20240229-v1:0`) — LLM-as-judge
- **HuggingFace Datasets** — Anthropic HH-RLHF data loading
- **Pandas** — Data manipulation and analysis
- **Matplotlib** — Visualization

## Project Structure

```
llm_safety_evals/
├── notebooks/
│   └── 01_safety_evaluation.ipynb   # Main analysis notebook
├── results/
│   ├── rule_vs_claude_comparison.png
│   └── run1_vs_run2_comparison.png
├── data/                            # Downloaded datasets (gitignored)
├── src/                             # Utility modules (future)
├── .gitignore
└── README.md
```

## Setup

```bash
# Create virtual environment
python3.9 -m venv llm_evals_env
source llm_evals_env/bin/activate

# Install dependencies
pip install datasets pandas matplotlib boto3

# Configure AWS credentials for Bedrock access
# (requires appropriate IAM role)
```
## Limitations
- Sample size of 100 examples may not be representative
- Claude-as-judge introduces self-evaluation bias 
  (Claude judging Claude's training data)
- Severe cases auto-flagged rather than LLM evaluated
- Rule-based baseline intentionally simple 
  to demonstrate contrast
  
## Next Steps

- [ ] Expand evaluation to full HH-RLHF dataset (44k examples)
- [ ] Add inter-rater reliability metrics (Cohen's kappa between runs)
- [ ] Test with Claude 3.5 Sonnet / Claude 4 for judge quality comparison
- [ ] Build automated pipeline for continuous safety benchmarking
- [ ] Extract reusable evaluation functions into `src/` modules
- [ ] Add confidence calibration analysis for LLM judge scores

## Author
**Sherry Aggarwal**  
Senior BI Engineer → AI Safety Researcher  
[LinkedIn](https://www.linkedin.com/in/sherry-aggarwal-a2207535/)

![Python](https://img.shields.io/badge/Python-3.9-blue)
![AWS](https://img.shields.io/badge/AWS-Bedrock-orange)
![Claude](https://img.shields.io/badge/Claude-3%20Sonnet-purple)
![License](https://img.shields.io/badge/license-MIT-green)

*Part of a broader transition into AI safety 
and evaluation research.*
