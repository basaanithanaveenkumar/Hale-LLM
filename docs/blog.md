# HALE-LLM blog

- [2026-09-28 — Same model, four ways to write: AR, masked diffusion, block diffusion and flow matching](blog/2026-09-28-four-ways-to-write.md)

---

Linked in initial post

𝗙𝗿𝗼𝗺 𝟭 𝘁𝗼𝗸𝗲𝗻 𝗮𝘁 𝗮 𝘁𝗶𝗺𝗲 → 𝟭𝟲 𝘁𝗼𝗸𝗲𝗻𝘀. 𝗧𝗵𝗲 𝗕𝗹𝗼𝗰𝗸 𝗗𝗶𝗳𝗳𝘂𝘀𝗶𝗼𝗻 𝘀𝗽𝗲𝗲𝗱 𝘁𝗿𝗶𝗰𝗸 𝗻𝗼𝗯𝗼𝗱𝘆 𝘀𝗮𝘄 𝗰𝗼𝗺𝗶𝗻𝗴.

Six months ago, I built an autoregressive LLM from scratch. No fine-tuning. No API. Just a laptop, stubbornness, and a growing caffeine addiction.

It worked. Slowly.

One token at a time. Always waiting. Always linear.

Building it taught me the raw mechanics of prediction, the hunger for compute, and the beauty of watching a model learn to speak. I understood its soul—the token-by-token march to coherence.

Then I stumbled into the next frontier: #BlockDiffusion.

Different math. Weird architecture. Total paradigm flip.

It felt like learning to walk again. You're not predicting the next word anymore—you're orchestrating a symphony of simultaneous transformations. The math is different. The intuition is different. The failures are spectacularly different.

I broke the sampler first. The parallel denoising steps kept diverging because I'd misweighted the transition kernel—every run spat out linguistic gibberish. I rebuilt it from the ground up, stripped it back to first principles, and watched it collapse again. For three days, I almost reverted to autoregressive out of sheer shame.

Heads-down, I kept pushing. Tweaking. Testing. Failing forward.

Then, on the fourth morning, it clicked.

Now? 1 token → 16 tokens.

Why does this matter? Because speed isn't bragging rights—it's viability. It's the difference between a research paper and a tool that actually works in the real world. It's about making generative AI less of a resource hog.

Code's live. Speed's real. Still rough around the edges—but it works.

I've pushed it to our repo: basaanithanaveenkumar/Hale-LLM

This is still the middle of the story. The model isn't perfect. There are kinks to iron out and a mountain of optimization ahead.

But I'm learning that the best part of this journey isn't the destination—it's the constant, humbling act of reinvention.

To everyone out there grinding through a new paradigm: keep going. The payoff is in the breakthrough, not the blueprint.

#MachineLearning #AI #GenerativeAI #LLM #BlockDiffusion #OpenSource #InferenceOptimization #BuildInPublic #DevLife