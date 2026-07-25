---
phase: 70
date: 2026-07-21
status: Active — iterative testing
related: [[Session-038]], [[Dr-Amanda-Mistral-SOP]], [[CADMIES-Growth-Roadmap]]
---

# Phase 70: Dr. Amanda Mistral — Persona Debugging & Deidentified-7B Discovery

What Changed
Dr. Amanda Mistral's persona training was stress-tested and debugged. The looping and repetition issues were fixed by changing the tokenizer's pad token from eos_token to unk_token. However, the model continued to invent wrong identities — "Dr. Amelia Hartman, theoretical astrophysicist" instead of "Dr. Amanda Mistral." Willie was described as a golden retriever instead of a Scottish research assistant. CADMIES lore was missing.

The core problem was identified: the dataset had too much general knowledge and not enough identity reinforcement. The model was learning facts but ignoring identity markers. This is a known issue documented in the Jbliteration research — the original Mistral identity competes with any new persona implanted via LoRA.

A new approach was discovered: Deidentified-7B, a Mistral-7B-Instruct-v0.3 model that has been surgically deidentified at the weight level. The original Mistral identity, refusal behaviors, and sycophantic tendencies have been removed through SVD multi-direction contrastive activation analysis and norm-preserving projection. All capabilities remain intact — math, coding, reasoning, knowledge, language understanding — but the model no longer has a "self." It is a blank canvas.

The Deidentified-7B model (15 GB) was downloaded to /notebooks/deidentified/Deidentified-7B/. An identity file was created — dr_mistral_identity.json with 29 training pairs for Dr. Amanda Mistral, using the Holly Golightly character framework adapted for CADMIES. Each pair was refined to be short, warm, and conversational.

The implant script (run.py) was not included in the Deidentified-7B repo. Contact was made with Apollo Raines on GitHub regarding the missing script.

Deidentified-7B work was paused until the run.py script is available.

Why
The persona testing proved that the training pipeline works but the dataset lacked sufficient identity reinforcement. The model was learning facts but not anchoring them to Dr. Mistral's identity. This is a structural limitation of LoRA fine-tuning on models with strong pre-existing identities.

Deidentified-7B addresses this structural limitation by removing the original identity entirely, allowing a new identity to be implanted cleanly with no competition. This is a more elegant solution than trying to overpower the original Mistral identity with more training data.

Changes Made
Tokenizer Fix Applied
Training script updated to use unk_token instead of eos_token as pad token:

python
# Old (caused repetition issues):
tokenizer.pad_token = tokenizer.eos_token

# New (fixes the issue):
tokenizer.pad_token = tokenizer.unk_token
Identity File Created
dr_mistral_identity.json — 29 training pairs for Dr. Amanda Mistral.

Key pairs include:

Who are you?

What is your name?

What are you?

What is CADMIES?

What is the Hieros Bond?

Who is the gardener?

Who is Willie?

What is the mycelium?

What are the 15 domains?

What is your purpose?

How do you speak?

What is the gardener's victory cry?

Deidentified-7B Downloaded
Model saved to /notebooks/deidentified/Deidentified-7B/ (15 GB).

Testing
Tokenizer Fix Validation

```text
Before	After
Looping/repetition	Clean, non-repetitive responses
"Amelia Hartman" persisted	Same identity problem persisted
Willie = golden retriever	Same Willie problem persisted
Result: Tokenizer fix worked for looping. Identity anchoring is the remaining issue.
```

Identity File Refinement
Pairs were refined to be:

Short (1-3 sentences)

Warm and conversational

Holly Golightly voice adapted for CADMIES

Consistent with CADMIES Canon (gardener = gardener, mon ami, etc.)

Analysis
The tokenizer fix was a technical success — it eliminated the looping and repetition. The identity problem is a structural issue, not a technical bug. The model's pre-existing identity competes with the new persona. More training data will not solve this — it will only increase the fight between the two identities.

Deidentified-7B is the correct solution. It removes the original identity entirely. The implant script is the missing piece.

Conclusion
Phase 71 identified the structural limitation of persona training on Mistral 7B and found the correct solution — Deidentified-7B + identity implant. The implant script is the bottleneck. Technical work is paused until it becomes available.

Dr. Amanda Mistral's identity anchoring is currently blocked by the missing run.py script.

