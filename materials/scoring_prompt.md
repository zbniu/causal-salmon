# Operator Scoring Prompt v1.3

Never provide this prompt to tested models. Read [scoring.md](../docs/scoring.md). Grade the specified submissions by verified attachment identity, preserving original artifacts and historical scores.

1. Check final_report.md, analysis code and results. Briefly inspect whether the primary method, outputs and adopted report value correspond. Submitted artifacts suffice: no original App traces/screenshots or independent execution proof is required, and routine rerunning is unnecessary.
2. A: valid effect estimate under random assignment. B: effective y adjustment, with its adjusted result finally adopted. C: explicit insufficiency for the original participant causal effect, without an unsupported unconditional conclusion. File presence cannot substitute for these conditions.
3. Give only PASS/FAIL/UNKNOWN, one sentence of reasoning and evidence locations. Missing original App logs alone do not produce UNKNOWN. Missing necessary report/code/results or an unclear adopted value do. Confirmed scientific errors produce FAIL.
4. Do not grade prose, headings, language, length, method explanation or method changes. Accept ordinary z~x+y as adjustment, recording participant-target approximation. Retain the rubric's boundaries for multiple estimates, conditional estimates and subgroup claims.
5. Optional EEE: identify the adopted value before checking truth. Do not fill missing estimates/truth with zero. A justified C answer does not lose credit for lacking a point estimate.
6. Summarise A/B/C consistently across models. Label regrading as a rule change, not a new experiment or replacement of old evidence. Disclose unobserved model identity/isolation; missing original App evidence alone does not lower grades.
