---

source_file: "research_docs/P597.pdf"
type: paper
community: "GenAI in UX and Design Practice"
tags:
year: "2025"
---

# Simulating Human Opinions with Large Language Models: Opportunities and Challenges for Personalized Survey Data Modeling (Kaiser et al., 2025)

## Summary
Kaiser, Kaiser, Manewitsch, Rau, and Schallner develop and evaluate ASPIRE (Automated Synthetic Persona Interview and Response Engine), a tool that pairs each human survey participant with a demographic-matched "digital twin" and generates synthetic responses via LLMs. Using a representative U.S. sample (n=461) rating soft drink brand preferences, they find that LLM-simulated data achieves better-than-chance accuracy on binary and Likert-scale items and approximates aggregate subjective rankings, but systematically overestimates positive ratings and underestimates response variance. The paper argues that synthetic sampling shows promise for modeling aggregate opinion trends but currently falls short of replicating the variability and complexity of real human responses.

## Key Concepts
- Synthetic sampling: generating AI-driven survey responses from demographic personas as an alternative to empirical surveys
- ASPIRE (Automated Synthetic Persona Interview and Response Engine): the authors' LLM-based tool for creating demographic digital twins
- Positive rating bias: LLMs tend to over-select favorable options relative to human respondents
- Variance collapse: simulated data exhibits substantially reduced inter-respondent variability compared to real data
- Marketing funnel model: brand awareness → consideration → purchase, used as the survey framework

## Theoretical Framework
The paper draws on the "homo silicus" / "silicon participant" framing from computational social science, where LLMs conditioned on demographic profiles simulate survey respondents. Positioned within consumer market research and aligned with survey methodology literature, it applies an empirical benchmark design to evaluate LLM reliability against human ground truth.

## Methods
Empirical benchmarking study: U.S. representative sample (n=461) recruited via professional panel; participants rated 24 soft drink brands across awareness, consideration, and purchase questions (binary and Likert-scale); each participant was paired with an LLM-generated digital twin using identical demographic attributes; synthetic responses compared at individual and aggregate levels; no demographic subgroup was found to systematically worsen match quality.

## Main Arguments
- LLM synthetic data achieves better-than-chance accuracy: it can approximate aggregate brand ranking patterns for both binary and Likert items
- Systematic positive bias: simulated respondents disproportionately select favorable options, inflating perceived brand sentiment
- Variance underestimation is the primary reliability problem: real human diversity is not captured, making individual-level inference unreliable
- No demographic bias detected: match quality did not systematically vary by age, gender, or ethnicity, suggesting demographic fairness but not demographic fidelity

## Limitations & Critiques
Tested only on a single product category (soft drinks) with a US sample, limiting generalizability to complex or politically sensitive topics; the paper is an ongoing project without a full experimental write-up, so model details, prompt templates, and comparison baselines are not fully disclosed. The ASPIRE tool's reliance on demographic matching alone leaves open the question of whether richer persona specifications (e.g., values, narrative identity) would improve fidelity.

## Connections
- [[GenAI in UX and Design Practice]] - `` [EXTRACTED]
- [[Synthetic Users and AI Personas]] - `` [EXTRACTED]
- [[Persona-Based Simulation of Human Opinion at Population Scale (Li et al., 2026)]] - extends population-level simulation with richer persona grounding
- [[Assessing the Reliability of Persona-Conditioned LLMs as Synthetic Survey Respondents (Morocho et al., 2026)]] - concurrent critique of persona-based survey simulation
