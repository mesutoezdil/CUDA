At some point, if you go deeper into GPUs, you will run into something called a “white paper”.

At first, it feels heavy. Too detailed. Maybe even unnecessary.

But over time, you realize something important.

White papers are the closest thing to the truth about a GPU.

No marketing. No simplification. Just how the hardware is actually built.

If you want to understand what a GPU really is, this is where you look.

Finding a white paper is simple.

Take the chip name. Add “white paper”.

For example: `GA100 white paper` or `H100 white paper`

But there is one detail that matters.

Not every result is useful.

You will find blog posts, summaries, comparisons. Those can help, but they are not enough.

What you want is always the official PDF.

That is where the real information lives.

After reading a few of them, you start noticing a pattern.

NVIDIA white papers are not random documents. They follow a consistent structure.

Each new architecture is usually explained in relation to the previous one.

So it is not just “what is new”, but also “what changed”.

That is why you often see the same tables across different white papers.

At first, it feels repetitive.

Later, you understand why it is useful.

Once you understand one white paper properly, the others become much easier to read.

Looking at GPU architectures as of 2026, there is a very clear direction.

Pascal was still mostly a general-purpose compute architecture.

With Volta, things changed. Tensor Cores were introduced, and GPUs became explicitly optimized for AI workloads.

Ampere expanded that idea. More throughput, better efficiency, and features like sparsity support.

Hopper pushed things further with FP8 and new execution models designed for large-scale AI systems.

And now with Blackwell, the shift is even more obvious.

New formats like NVFP4 bring ultra-low precision directly into hardware. 

This is not a small step. It changes how large models are deployed and scaled.

At this point, GPUs are no longer just compute devices.

They are infrastructure for AI systems.

<arch-timeline focus="Pascal"></arch-timeline>

When reading a white paper, one section matters more than anything else:

The Streaming Multiprocessor (SM).

This is the core of the GPU.

Everything comes together here:

* CUDA cores
* Tensor cores
* Scheduling
* Memory access

If you want to understand what really changed in an architecture, this is where you look.

You can see the evolution clearly:

Pascal has no Tensor Cores. Volta introduces them. Ampere improves and scales them. Hopper optimizes them for transformer workloads. Blackwell extends them with new precision formats and instructions.

These are not small improvements.

Each step changes what the GPU is designed to do.

Another thing you notice over time:

Even though architectures change, the way they are documented does not.

The structure stays consistent.

First, new features are introduced. Then the SM design is explained. Then performance comparisons are shown. Finally, the technical specifications are listed.

This consistency is intentional.

It makes it easier to follow the evolution across generations.

<whitepaper-map></whitepaper-map>

In practice, reading white papers is not about memorizing numbers.

It is about understanding change.

Look at the SM, identify new hardware units and compare with the previous generation.

That is where the real story is.