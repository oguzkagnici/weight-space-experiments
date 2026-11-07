# stack_shortans_L23_finalist_L22: generation 7's two in-scope mechanisms stacked on the parent

The two mechanisms touch disjoint tensors (layer 23 and layer 22), so the stack is a plain union of the two edits.

1. **`ed_a_g7_short_answer_dupfold_L23`** (`ed_a`, generation 7).
   - Slots are freed in a cluster of near-duplicate L23 neurons: `w2[:,1228] += w2[:,3401] - w2[:,3793] - w2[:,6986]`.
   - Three gated units fill them: `</think>` -> '"The', '"The' -> ' answer', and ')".' -> `<|im_end|>`. The visible answer becomes exactly "The answer is (X)", with the letter copied from the thinking.
   - It targets traces that close the thinking late and are then cut inside the ~250-token re-derivation.
   - Generation-7 selection: +3.1 pp (SE 2.9, z 1.08, +9/-5).
2. **The two-finalist commit at L22 n1786** (`claude`, generation 7; built but not submitted).
   - The gate is the mean-difference direction between paragraph breaks that end a two-finalist statement and other breaks (LOTO AUC 0.864), with a bias-proxy threshold of 7.5 and k 6.
   - The gate row is projected off the prompt-sink subspace, so prompt tokens do not fire it.
   - w3 = mu_hat/mp; the w2 column writes commit openers minus deliberation openers, clipped to the Q8 block absmax.
   - Paired on all 96 bank questions: +1.0 pp (SE 2.8, +4/-3). After a two-finalist paragraph, a commit opener follows in 10/29 cases vs 3/39 for the parent.

**Why carry it:** each mechanism converts a different, rare kind of cut trace. Every edit resamples traces, so neither can pass alone. The stack tests whether their gains add up on a fresh selection set.
