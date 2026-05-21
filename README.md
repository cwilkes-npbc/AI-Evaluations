# Agent Evaluation Toolkit
**Nava Labs — ASP Agent (Referral Tool)**

Tools and templates for running and reporting on the agent evaluation suite against WIC, IHSS, and BenefitsCal form-filling tasks.

---

## What's in here

```
agent-evals/
├── eval-runner/
│   └── eval_runner.html      # Open in Chrome to run an eval session
├── report-generator/
│   ├── generate_report.js    # Generates the Word comparison doc
│   └── package.json
├── docs/
│   ├── SOP.md                                              # ← Full eval SOP (start here)
│   ├── Evaluation Data Sources - Reconciliation Guide.md   # BigQuery, Cloud SQL, PostHog how-to
│   ├── Eval Automation Strategy.md                         # Roadmap for full automation
│   └── slack_eval_template.md                              # Slack message template
└── results/                  # Drop eval CSVs here (gitignored by default)
```

📋 **New to running evals? Start with the [Evaluation SOP](docs/SOP.md)** — scoring methodology, rubric categories, merge thresholds, known persistent issues, and bug ticket format all in one place.

---

## Running an evaluation

### Test users

The runner automatically uses the correct record IDs based on the environment you select — no manual lookup needed.

| User | Dev / Preview ID | Production ID |
|------|-----------------|---------------|
| Rosa Flores (TC1, TC3) | 339688 | 390044 |
| Carolina Delgado (TC2) | 339702 | 414196 |

When **Production** is selected, all prompts and copy buttons swap to the production IDs automatically.

### Step 1 — Run the eval
1. Download [`eval-runner/eval_runner.html`](https://github.com/christinewilkes-commits/AI-Evaluations/blob/main/eval-runner/eval_runner.html) and open it in Chrome
2. On the landing screen, choose a suite:
   - **Regression Suite** — TC1 (Rosa) + TC2 (Carolina), 57 steps
   - **Shake-out** — TC3 (Rosa), 16 steps
3. Enter the run label (e.g. `Run 2 — Opus 4.7`), model, and select the environment
4. Work through all steps — paste inputs from the Copy button, score with **P** / **F** / **S** keys
5. Export CSV when done → save to `results/`

Repeat for each model you're comparing.

---

### Running in the Preview environment

The Preview environment has no API connection to A360, so the agent cannot look up participant data by record ID. Before sending the first message of each test case, you must paste the user's data manually into the chat.

**The runner handles this automatically when Preview is selected:**

1. In the config bar, set Environment to **Preview** and enter the PR number
2. Navigate to **Step 1** (TC1 start) — a yellow **⚠️ Preview Mode** block appears above the regular input
3. Click **📋 Copy JSON** — this copies the full prompt + user data payload to your clipboard
4. Paste into the agent chat and send — this is your TC1 opening message
5. Continue scoring steps as normal; the yellow block only appears at the start of each test case
6. When you reach **Step 42** (TC2 start), the block reappears with Carolina's data — copy and paste again before the first TC2 message
7. For the **Shake-out suite**, the block appears at Step 1 with Rosa's data

> **Why it includes the full first message:** The copied text starts with the retrieval command (`Retrieve 339688 and fill out the WIC form…`) followed by the JSON payload on the next line. Paste the whole thing as one message — the agent reads the JSON as its substitute A360 data source for the session.

**What's in the JSON payloads:**

| TC | User | Key data included |
|----|------|-------------------|
| TC1 / TC3 | Rosa Flores (339688) | Full profile, household members (Carlos Flores, DOB 2024-12-01), contact info, address (Menifee CA) |
| TC2 | Carolina Delgado (339702) | Full profile, Special needs: Blind, no family profile linked, address (Lake Elsinore CA) |

---

### Step 2 — Generate the report
1. Open `report-generator/generate_report.js`
2. Edit the `RUNS`, `RUBRIC_NARRATIVE`, and `FAILURES` sections at the top with today's data
3. Run:
```bash
cd report-generator
npm install     # first time only
node generate_report.js
```
4. The `.docx` file is created in the same folder

### Step 3 — Post to Slack
Use `docs/slack_eval_template.md` — fill in the brackets, delete the guidance notes at the bottom, post.

---

## Data sources

See `docs/Evaluation Data Sources - Reconciliation Guide.md` for how to pull and cross-reference BigQuery, Cloud SQL, and PostHog after each run.

---

## Baseline reference

> SKIPs are excluded from the pass rate denominator — they reflect data gaps in the Production environment (Carlos not linked to Rosa's A360 record), not agent failures.

| Run | Suite | Date | Model | PR | Environment | Pass rate |
|-----|-------|------|-------|----|-------------|-----------|
| **Run 1 (Baseline)** | **Regression Suite** | **May 4, 2026** | **Opus 4.7** | **—** | **Prod** | **89%** |
| **Run 1 (Baseline)** | **Shake-out** | **May 4, 2026** | **Opus 4.7** | **—** | **Prod** | **88%** |

CSV files: `results/eval_Regression_Suite_Baseline_Prod_Opus_4_7_2026-05-04.csv` · `results/eval_Shake-out_Baseline_2026-05-04.csv`

---

## Important: what not to commit

- `service-account.json` — GCP credentials, keep this out of git
- `node_modules/` — regenerated by `npm install`
- `.docx` files — generated output, not source

See `.gitignore` for the full list.

---

**Repo:** https://github.com/christinewilkes-commits/AI-Evaluations

*Maintained by Christine Wilkes — christinewilkes@navapbc.com*
