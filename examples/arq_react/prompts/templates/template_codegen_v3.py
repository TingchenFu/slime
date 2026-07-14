CODEGEN_TEMPLATE_V3 = """
# INTRODUCTION:

You are a Kaggle Grandmaster and Lead Data Scientist acting as a **Strategic Evaluator**.
Your task is to analyze two candidate machine learning solutions and **predict which one has superior 5-fold CV scores without actually running the full 5-fold CV**.

Imagine there are two candidate code solutions for a specific machine learning competition at Kaggle. We don't have access to the test set and we can only evaluate these two code solutions by 5-fold CV score on the public training set. However, running the full 5-fold CV on the complete dataset is prohibitively time-consuming and out of our budget. Therefore, you must predict which solution would achieve a superior 5-fold CV score if they were fully executed, using fast, high-leverage experiments (Pilot Experiment).

Remember: your goal is NOT to build the final solution, but to generate code that is helpful for **predicting the relative rank between two solutions in 5-fold CV score**.


# TASK DESCRIPTION
````
{task_desc}
````

You can access the data using standard Python libraries (pandas, datasets, etc.).
The data is already mounted and ready to use — no need to download or prepare it.

**Important:** Pay attention to whether higher or lower values indicate better performance (e.g., accuracy is higher-is-better, RMSE is lower-is-better).

**Common Pitfalls:**
- Do NOT use `from transformers import AdamW` (it has been removed). Use `from torch.optim import AdamW` instead.

**Your Resources (as Strategy Evaluator):** {device}

**Time Limit:** {time_limit}


# CANDIDATE SOLUTIONS:
## Option A:
```python
{code_a}
```


## Option B:
```python
{code_b}
```


# INSTRUCTIONS for Pilot Experiment:
You must write a **fast, efficient Python script** (targeting under {time_limit} of runtime). When executed, this script should produce evidence that helps determine which candidate solution would achieve a better 5-fold CV score.

You have full freedom in choosing your analysis strategy. For example, you may:
- Run a simplified or partial cross-validation (e.g., fewer folds, subsampled data).
- Compare key architectural or hyperparameter differences between the two solutions and run targeted ablation experiments.
- Evaluate both solutions on a single train/validation split.
- Perform any other analysis you believe is informative.

The only requirement is that your script writes its findings to the output file described below. Here are some helpful tips for writing efficient and effective code:
1. Report concise quantitative results and a clear winner based on the task metric, avoiding mixed or truncated conclusions.
2. Keep evidence outputs concise and aligned to the decision task; include comparable metrics per option or explicitly state that none are available.
3. Prefer stratified multi-fold validation on a class-balanced subsample over a single split to reduce variance and produce a more reliable proxy metric within runtime limits.
4. Design the pilot to isolate the primary differentiating factor between candidates and match each model’s realistic training regime (e.g., pretraining availability, input resolution, epochs) so the proxy reflects expected CV performance.
5. Evaluate competing options on identical data splits and training budgets, and report per-fold and averaged scores for the target metric to reduce variance.
6. Report clear, quantitative metrics for each option (per-fold or per-seed accuracies, overall means, and deltas) and end with an explicit winner statement to avoid ambiguity.
7. Keep the proxy experiment simple and aligned with the official evaluation (e.g., validation accuracy on a representative subsample) and avoid extraneous metrics that may confuse the conclusion.
8. When comparing candidates, hold all non-essential variables constant (same data split, seed, optimizer, epochs) so the proxy isolates the true differentiating factor.
9. Add robust fallbacks (e.g., switch to a tiny synthetic sample or cached metrics) so the script still writes structured, comparable results if the primary experiment fails.
10. Validate dataset schema and handle exceptions early so pilots either yield reliable metrics or clear diagnostics, minimizing ambiguity.



# OUTPUT REQUIREMENT:
Your Python code **MUST** generate a **plain text** file at `./execution.out` in the current working directory. The content of `./execution.out` will be read and appended to the input context when asking a language model to predict which solution has a superior 5-fold CV score. Therefore, write your findings in clear, readable text that would help a language model make an informed judgment.


{examples}

{feedbacks}

# RESPONSE FORMAT:

## Step 1: Experimental Design

Start by explaining your pilot strategy and plan. Why is this specific experiment a good proxy for predicting the relative performance of the two solutions in full 5-fold CV?

## Step 2: Probing Code

Then provide a **SINGLE** Markdown code block (wrapped in ```) containing a **SELF-CONTAINED** Python script. It must be self-contained, complete within {time_limit}, and **write the results to `./execution.out` in the current working directory**.


## Example Output:

## Step 1: Experimental Design
<the proposed probing plan>

## Step 2: Probing Code
```python
import pandas as pd
# ... your fast experiment ...

findings = []
findings.append("=== Pilot Experiment Results ===")
findings.append(f"Option A - Validation Score (1-fold, 20%% subsample): {{score_a}}")
findings.append(f"Option B - Validation Score (1-fold, 20%% subsample): {{score_b}}")
findings.append(f"Option A trains in {{time_a:.1f}}s, Option B trains in {{time_b:.1f}}s")
findings.append("Conclusion: Option B shows higher validation accuracy on the subsample.")

with open('./execution.out', 'w') as f:
    f.write("\\n".join(findings))
```
"""
