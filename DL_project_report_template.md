# [Title: what you reproduced and how you improved it]

**Deep Learning · M.Sc. Applied Data Science and AI · SRH University Munich · Winter semester 2026/27**
**Author(s):** [name(s)] · **Repository:** [link to your GitHub repository] · **Date:** [date]

> How to use this template: copy it into your repository as `report.md` (or into LaTeX or Word with the same sections).
> Replace everything in [square brackets]. Keep the section titles: they follow the grading criteria (weights in brackets).
> Start now with section 2 (the data). There is no page limit; aim for clarity, not length: every number with its source, every claim with evidence.

---

## Abstract

[Four or five sentences: the task, the paper, the data, your reproduced result next to the published one, your improvement and its measured effect (mean ± spread).]

## 1 · The paper and the task (research understanding, part of 15 %)

- **Paper:** [authors, title, venue, year, link]
- **Task:** [what goes in, what comes out; for example "a 64 × 64 satellite image → one of 10 land-use classes"]
- **Their method in your own words:** [architecture, loss, training; a figure of your own if it helps]
- **Their main result:** [the number(s) you want to reproduce, with table/figure number in the paper]

## 2 · The data (start this week)

| | |
|---|---|
| Source and version | [where from, which version, download date] |
| Licence | [licence, and what it allows] |
| Size | [number of samples, size of each sample] |
| Classes or targets | [list; class balance as counts or a bar chart] |
| Splits | [training / validation / test sizes; **how** you split: random, grouped (by patient, place, …), by time; why] |
| Preprocessing | [resizing, standardisation (statistics from the training set only), cleaning] |
| Leakage checks | [duplicates between splits? the same patient/place/time in two splits? preprocessing fitted on all data? what you did about it] |
| Shared with Biomedical Image Analysis? | [yes/no; if yes: which preparation was done for BIA, and say that it is not graded again here] |

[Two or three example samples per class, as a figure.]

## 3 · Reproducing the baseline (part of 15 %, and 25 % implementation)

**The recipe:** read the paper (or its code) like a recipe. One row per ingredient; leave nothing empty: if the paper does not say it, write "not stated" and what you chose.

| | The paper says | Where (page, table, code) | What we use |
|---|---|---|---|
| Data: version, split | | | |
| Model: layers, sizes, pretrained? | | | |
| Training: optimiser, learning rate, schedule | | | |
| Training: epochs, batch size | | | |
| Augmentation and preprocessing | | | |
| Metric, and how it was averaged | | | |

- **Setup:** [framework and versions; anything not in the table]
- **What the paper did not say,** and what you chose instead: [list, from the "not stated" rows]

| | Paper | Ours (mean ± spread, n seeds) |
|---|---|---|
| [metric] | [value] | [value] |

[Why the numbers differ, if they do: data version, preprocessing, compute, missing details. A difference that you explain is a result, too.]

## 4 · Your improvement (20 %)

- **Idea:** [what you change]
- **Why it should help:** [the reasoning: a weakness of the baseline you observed, a method from the course or from another paper]
- **Expected effect:** [what you expect to see, and on which metric]

## 5 · Experiments (part of 20 % and 15 %)

- **Design:** one change at a time; the same data splits, the same budget; at least three seeds per setting.

| Setting | [metric] mean | ± spread | seeds |
|---|---|---|---|
| baseline | | | |
| + [change 1] | | | |
| + [change 2] | | | |

- **Statistical comparison:** [test and result, for example a paired test over seeds or folds (Session 31)]
- **Test set:** used **once**, for the final models only.

## 6 · Evaluation and error analysis (15 %)

- [Metrics that fit the task (not only accuracy): confusion matrix, precision, recall, F1, IoU, …]
- [Where does the model fail? Examples of its most confident mistakes; which classes are confused, and why]
- [Limitations: what your results do **not** show]

## 7 · Conclusion

[What you reproduced, what you improved, what you would try next.]

## 8 · Use of AI tools (5 %)

[Which tools you used, for what (code, text, debugging), and how you **checked** their output. Be specific.]

## 9 · Reproducibility (part of 25 %)

- **Run it:** [the commands or notebook order; the environment, for example `requirements.txt`]
- **Seeds and hardware:** [seeds used; GPU or CPU; training time]
- **Where the results come from:** [which notebook/script makes which table and figure]

## References

[All papers, data sets, code and websites you used.]
