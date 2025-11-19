Machine Learning- HomeAssingmnet 5
--------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------
University Of Central Missouri 

Student Information

Name: Nikhilesh Katakam 

700#: 700772365

Course: CS5710 — Machine Learning Semester Fall 2025 

Assignment: Home Assignment 5
--------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------

📌Overview 
--------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------

This repository contains my solutions for Home Assignment 5, which covers two main components:

Part A — Short-Answer Questions Focused on Transformers, Positional Encoding, Attention Mechanisms, Multi-Head Attention, Ethics in AI, Dataset Bias, and AI-related Harms.

Part B — Coding Tasks

Q1: Implementation of Scaled Dot-Product Attention using NumPy

Q2: Implementation of a Simple Transformer Encoder Block using PyTorch

Includes Multi-Head Self-Attention, Feed-Forward Network, LayerNorm, Residuals, and Shape Verification

All code is fully commented as required and structured for clarity.
--------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------

📍Part A — Short Answer Summary

The written answers include detailed explanations on:

✔ Positional Encoding

Why Transformers need positional encodings

Requirements for good encoding schemes

Unitary & norm-preserving positional matrices

✔ Attention Mechanism

Definition of attention scores

Role of softmax

Computation of context vectors

✔ Multi-Head Attention

Advantages of multiple heads

Subspace projection

Why concatenation + linear projection is needed

✔ Ethics in AI

Difference between ethics, laws, and feelings

Utilitarian vs Deontological reasoning in AI decisions

Why no single ethical theory dominates

✔ AI Harms

Allocational vs representational harms

Real-world examples

Why representation harms are harder to measure

✔ Dataset Bias

Sources of bias

Underrepresented groups

Bias amplification

✔ Security & Privacy

Data poisoning

Model memorization

Model stealing

🧑‍💻 Part B — Coding Q1 — Scaled Dot-Product Attention (NumPy)

This script implements:

Stable softmax

Scaled dot-product attention

Optional masking

Test demonstrating correct output shapes

Q2 — Transformer Encoder Block (PyTorch)

This script includes:

Multi-Head Self-Attention implemented manually

Feed-Forward Network

Add & Norm layers

Residual connections

Dropout

Shape verification test

⚙️ Dependencies

Ensure you have the following installed:

Python Libraries pip install numpy torch

Versions used during development:

Python 3.10

NumPy 1.26+

PyTorch 2.0+
