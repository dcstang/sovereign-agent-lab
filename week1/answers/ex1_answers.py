"""
Exercise 1 — Answers
====================
Fill this in after running exercise1_context.py.
Run `python grade.py ex1` to check for obvious issues before submitting.
"""

# ── Part A ─────────────────────────────────────────────────────────────────

# The exact answer the model gave for each condition.
# Copy-paste from your terminal output (the → "..." part).

PART_A_PLAIN_ANSWER    = "The Haymarket Vaults" 
PART_A_XML_ANSWER      = "The Albanach"
PART_A_SANDWICH_ANSWER = "The Albanach"

# Was each answer correct? True or False.
# Correct = contains "Haymarket" or "Albanach" (both satisfy all constraints).

PART_A_PLAIN_CORRECT    = True
PART_A_XML_CORRECT      = True
PART_A_SANDWICH_CORRECT = True

# Explain what you observed. Minimum 30 words.

PART_A_EXPLANATION = """
This is the simplest problem, where the LLM is about to answer correctly without much issue. the answer is clean and no hallucination is seen. Good as a baseline check, for comparing with the subsequent more difficult tasks to get a sense of how different levers affect the output.
"""

# ── Part B ─────────────────────────────────────────────────────────────────

PART_B_PLAIN_ANSWER    = "The Haymarket Vaults"
PART_B_XML_ANSWER      = "The Albanach"
PART_B_SANDWICH_ANSWER = "The Albanach"

PART_B_PLAIN_CORRECT    = True
PART_B_XML_CORRECT      = True
PART_B_SANDWICH_CORRECT = True

# Did adding near-miss distractors change any results? True or False.
PART_B_CHANGED_RESULTS = False

# Which distractor was more likely to cause a wrong answer, and why?
# Minimum 20 words.
PART_B_HARDEST_DISTRACTOR = """
Seems that the near miss distractors did not change anything on the output. I suppose that the frontier models are able to distinguish this problem easily and check each of the requirements from the user. So part A and part B are all correct without any real effect or difference in outcome. Seems we can't distinguish between the effect of the format XML etc as well.
"""

# ── Part C ─────────────────────────────────────────────────────────────────

# Did the exercise run Part C (small model)?
# Check outputs/ex1_results.json → "part_c_was_run"
PART_C_WAS_RUN = True

PART_C_PLAIN_ANSWER    = "The Haymarket Vaults"
PART_C_XML_ANSWER      = "The Haymarket Vaults"
PART_C_SANDWICH_ANSWER = "The Haymarket Vaults"

# Explain what Part C showed, or why it wasn't needed. Minimum 30 words.
PART_C_EXPLANATION = """
It seems completely the same. Thought a smaller 8B model returns the Haymarket for all answers; it is also similarly acceptable as an outcome. The smaller model was not deterred by the clean data or SNR. In this case I would go for 8B for this kind of task then.
"""

# ── Core lesson ────────────────────────────────────────────────────────────

# Complete this sentence. Minimum 40 words.
# "Context formatting matters most when..."

CORE_LESSON = """
A 8B model was sufficient in performing the task and distinguishing the requirements from the user regardless of the noise to signal ratio. In terms of cost and performance, efficiency, I would rather take the 8B model as the main model for this kind of use case in the future. It was useful to experiment with the other formats but my take is that newer models are quite robust to formating and primacy or recency issues.
"""
