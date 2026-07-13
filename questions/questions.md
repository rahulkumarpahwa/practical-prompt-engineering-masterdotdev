1. What is prompt engineering according to OpenAI's definition?
1. Prompt engineering is the process of writing effective instructions for a model such that it consistently generates content that meets your requirements. Because the content generated from a model is nondeterministic, prompting to get your desired output is a mix of art and science. However, you can apply techniques and best practices to get good results consistently.

2. How do Large Language Models (LLMs) generate their outputs?
2. LLMs are pattern predictors that generate one token at a time. They predict the next most likely token based on the input provided. The generation happens token by token with no planning ahead, meaning LLMs only 'think' while they are typing. They will most often predict the next most likely token, but sometimes may predict other likely tokens instead.

3. What is the difference between deterministic and nondeterministic systems, and which category do LLMs fall into?
3. Deterministic systems, like calculators, always produce the same output for a given input (e.g., 2 + 2 always equals 4). Nondeterministic systems can produce different outputs for the same input. LLMs are nondeterministic, meaning if you enter the same prompt multiple times, you will likely get different answers each time. This is because they predict tokens based on probability, not fixed rules.

4. What limitation do LLMs have regarding their training data, and how does this affect their reliability?
4. LLMs are trained on data collected up to a certain cutoff date. While many LLMs now have multi-modality features like internet searching that allow them to find information after their cutoff date, information before the cutoff date tends to be more reliable. This is because post-cutoff information may only exist in limited sources, making the LLM's responses potentially less accurate for very recent events or new technologies.

5. What breakthrough did the 'Attention Is All You Need' research paper introduce, and how did it improve language models?
5. The 2017 'Attention Is All You Need' research paper introduced the transformer architecture with an attention mechanism. This allowed models to pay attention to thousands of words at a time instead of just 5-10 words like phone autocomplete. The architecture also enabled models to learn which tokens mattered most for predictions. Additionally, the paper revealed scaling laws showing that when model size increased by 10X, capability increased by 100X, leading to models that can now handle over a million tokens.

6. What happens when the temperature parameter is set to 0 in a Large Language Model?
6. When temperature is set to 0, the LLM becomes essentially deterministic and will always pick the next most likely token. It provides the most predictable and consistent output.

7. For what types of tasks should you use a lower temperature setting in an LLM, and why?
7. Lower temperature settings are better for factual tasks, code generation, and data extraction. This is particularly important for applications in healthcare or banking where you want the LLM to behave very specifically and avoid making assumptions or guessing low-percentage tokens.

8. What is Top P and how does it differ from temperature in controlling LLM randomness?
8. Top P is a cumulative probability cutoff that limits which tokens the LLM can consider based on their likelihood. Unlike temperature which controls how often the most likely token is picked, Top P restricts the pool of available tokens. For example, setting Top P to 0.5 means only tokens within the top 50% most likely options are considered.

9. If an LLM has token options of blue (75% likelihood), gray (20% likelihood), and orange (5% likelihood), what tokens would be available if Top P is set to 0.5?
9. Only blue would be available. Setting Top P to 0.5 means only tokens within the top 50% cumulative probability are considered. Since blue represents 75% of the probability, it's the only token within the 50% threshold, cutting out both gray and orange as options.

10. What happens when the temperature parameter is set to its maximum value of 2 in an LLM?
10. At temperature 2, the output becomes completely illegible and chaotic. It won't even be broken English—it will just be randomness. This setting is never practically used because the output is unusable.