+++
title = "LLM fine-tuning - Theory and practice"
description = "Large language models (LLMs) are now ubiquitous in many applications. However, it can be the case that an off-the-shelf model does not perform well in a specific task, or that we would like a smaller model focused on some specific use cases and avoid expensive, large general-purpose models. In these cases, we need to find a way to “tweak” the behaviour of a model to fit the requirements. This beginner-friendly workshop, organized by the Sweden AI Factory, provides an introduction to LLMs and how their behaviour can be modified."

[taxonomies]
skill = ["ai", "programming"]
difficulty = ["beginner"]
maturity = ["stable"]

[extra]
tags = ["python", "deep-learning"]
external_url = "https://learn.SwedenAIFactory.se/roadshow/"
+++

This beginner-friendly workshop provides an introduction to LLMs and how they work, followed by how their behaviour can be tweaked by prompt engineering, RAG and fine-tuning.

## Key takeaways

By the end of this course, you will be able to:

- explain how text becomes a sequence of contextual token representations;
- describe the roles of tokenisation, embeddings, attention, and feed-forward layers;
- distinguish a problem with instructions from a problem with evidence;
- choose between prompting, RAG, and fine-tuning for a concrete use case;
- explain why fine-tuning is not a reliable substitute for document retrieval;
- describe the difference between full fine-tuning and parameter-efficient fine-tuning;
- explain the central idea behind low-rank adaptation;
- design a baseline and evaluation before introducing additional complexity;
- describe the main ways of evaluating a trained LLM and the limitations of each;
- interpret benchmark results with appropriate caution.

## Who is this for?

The lesson is intended for researchers, research software engineers, and technical staff who want to understand how large language models can be adapted to specialist tasks.
The main focus is not on any particular model or software library (our example will be, though). Instead, the lesson develops a conceptual framework that can be applied when planning an LLM-based application or a fine-tuning experiment.

## Prerequisites

- Basic familiarity with Python
- Some familiarity with linear algebra
- If you have used a LLM-based chat application it’d be beneficial
- Some basic understanding of how a machine learning/deep learning model is trained at a general level
