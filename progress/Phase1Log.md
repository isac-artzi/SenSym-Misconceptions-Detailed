# Phase 1 — <The design, and why it is this shape>   (8/26/26-8/29/26)

**5 hours:** 5

## What I worked out

- [proved] The pilot measures misconception detection rather than student learning because detection is a necessary first step before evaluating whether tutoring improves learning.
- [proved] The positive class is M (responses containing a misconception).
- [proved] The four confusion-matrix categories are TP, TN, FP, and FN.
- [proved] Accuracy, precision, recall, and F1 measure different aspects of model performance.
- [proved] Recall is the headline metric because missing a real misconception is the most important failure mode for this application.
- [proved] The dataset is balanced at 20 M / 20 C, giving a 50% majority-class baseline.
- [conjectured] The misconception-aware condition will increase recall more than precision.
- [proved] The decoy condition helps determine whether an improvement comes from the specific misconception catalogue or simply from the structure of the prompt.
- [proved] The experiment needs to define what outcomes would support or contradict the hypothesis before seeing the results.

## What I built / ran

- No new code or experiments were run during this phase.
- Reviewed the experimental design and prepared for the model-evaluation phase.

## Numbers this week

- No experimental results yet.
- Dataset design: **40 total responses**
- **20 M / 20 C**
- **10 misconception categories**
- Majority-class baseline: **50%**

## Checks

- Reviewed the baseline, misconception-aware, and decoy conditions.
- Verified the intended 20 M / 20 C class balance.
- Worked through confusion-matrix examples and metric calculations.
- Reviewed the pre-registered prediction and possible outcomes.
- [If true] Confirmed the repository tests/experimental setup described in the phase documentation.

## Where I'm stuck

- No major blockers at this stage.
- Next step is implementing/running the model evaluation in Phase 2/4.

## Wins

- Finished understanding the experimental design well enough to explain why the pilot focuses on detection rather than learning.
- Established the role of the decoy condition and why it is important for interpreting the results.
- Finished the research CSV/dataset preparation.

## Questions for the check-in

- Is the current experimental design sufficiently controlled for the main comparison?
- Is there anything I should clarify or change before beginning the model runs?
- Is the planned recall-focused evaluation appropriate for the research question?

## Tools used

Tools used: ChatGPT was used to help clarify and breakdown the Phase 1 research-design documentation; it was not used to generate experimental results.
