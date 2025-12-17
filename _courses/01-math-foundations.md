---
layout: course
title: "Math Foundations for AI/ML"
short_description: "Essential mathematical concepts including linear algebra, calculus, probability and statistics"
description: "Master the mathematical fundamentals required for AI and Machine Learning"
credits: 4
level: "Beginner to Intermediate"
instructor: "Faculty"
topics:
  - Linear Algebra Basics
  - Vectors and Matrices
  - Calculus Fundamentals
  - Probability Theory
  - Statistical Methods
  - Optimization
  - Principal Component Analysis (PCA)
  - SVM Optimization (Primal/Dual)
github_repo: "https://github.com/shivam2003-dev/semester_1_all_course"
---

## 📝 Course Overview

This course provides the mathematical foundation necessary for understanding machine learning algorithms and AI concepts. Whether you're new to mathematics or need a refresher, this course builds your skills systematically.

---

## 📚 Course Content

### Module 1: Linear Algebra Basics

<div class="alert alert-note">
  <h4>📌 Note: Linear Algebra is Crucial</h4>
  <p>Linear algebra is the backbone of machine learning. Understanding vectors, matrices, and their operations is essential for grasping how neural networks and most ML algorithms work.</p>
</div>

#### Key Topics:
- **Vectors and Vector Spaces**: Understanding n-dimensional spaces
- **Matrices**: Operations, inverse, determinant
- **Eigenvalues and Eigenvectors**: Critical for PCA and other techniques
- **Matrix Decomposition**: LU, QR, SVD decompositions

#### Important Concepts:

<div class="alert alert-warning">
  <h4>⚠️ Warning: Matrix Dimensions</h4>
  <p>Always check matrix dimensions before operations. For matrix multiplication A×B, the number of columns in A must equal the number of rows in B. This is a common source of errors!</p>
</div>

**Key Formulas:**
```
Matrix Multiplication (A: m×n, B: n×p → C: m×p)
C[i,j] = Σ A[i,k] × B[k,j]

Eigenvalue Equation:
Av = λv (where v is eigenvector, λ is eigenvalue)

Determinant (2×2):
|A| = ad - bc for matrix [[a,b],[c,d]]
```

<div class="alert alert-tip">
  <h4>💡 Industry Tip: GPU Computing</h4>
  <p>In industry, linear algebra operations are heavily optimized on GPUs. Libraries like CUDA and cuBLAS can make calculations 100x faster. Learn PyTorch or TensorFlow for practical implementation.</p>
</div>

---

### Module 2: Calculus Fundamentals

#### Key Topics:
- **Derivatives**: Understanding rates of change
- **Partial Derivatives**: Multivariable calculus
- **Chain Rule**: Essential for backpropagation
- **Gradient Descent**: Optimization algorithm
- **Integration**: Area under curves, probability

<div class="alert alert-note">
  <h4>📌 Note: Calculus and Neural Networks</h4>
  <p>The chain rule in calculus is the foundation of backpropagation in neural networks. Understanding how derivatives compose is critical for deep learning.</p>
</div>

**Essential Derivatives:**
```
d/dx(x^n) = n×x^(n-1)
d/dx(e^x) = e^x
d/dx(ln(x)) = 1/x
d/dx(sin(x)) = cos(x)

Chain Rule:
d/dx[f(g(x))] = f'(g(x)) × g'(x)

Gradient Vector:
∇f = [∂f/∂x₁, ∂f/∂x₂, ..., ∂f/∂xₙ]
```

<div class="alert alert-danger">
  <h4>🔴 Common Mistake: Chain Rule</h4>
  <p>Students often forget to multiply by the derivative of the inner function. Always apply the chain rule correctly in nested functions.</p>
</div>

<div class="alert alert-success">
  <h4>✅ Exam Tip: Gradient Descent</h4>
  <p>Exam questions often ask about gradient descent convergence. Remember: learning rate matters! Too high = divergence, too low = slow convergence. Be able to explain this with an example.</p>
</div>

---

### Module 3: Probability Theory

#### Key Topics:
- **Probability Basics**: Sample spaces, events
- **Conditional Probability**: Bayes' theorem
- **Random Variables**: Discrete and continuous
- **Probability Distributions**: Normal, Binomial, Poisson
- **Expectation and Variance**: Statistical measures

<div class="alert alert-info">
  <h4>ℹ️ Important: Bayes' Theorem</h4>
  <p>Bayes' theorem is fundamental to many ML algorithms. It describes the relationship between conditional probabilities and is the basis for Bayesian inference.</p>
</div>

**Key Formulas:**
```
Probability: P(A) = Number of favorable outcomes / Total outcomes

Bayes' Theorem:
P(A|B) = P(B|A) × P(A) / P(B)

Expectation: E[X] = Σ x × P(x)

Variance: Var(X) = E[X²] - (E[X])²

Normal Distribution:
f(x) = (1/(σ√(2π))) × e^(-(x-μ)²/(2σ²))
```

<div class="alert alert-warning">
  <h4>⚠️ Warning: Independence Assumption</h4>
  <p>Many algorithms assume feature independence, which is rarely true in practice. This can lead to suboptimal model performance if ignored.</p>
</div>

---

### Module 4: Statistical Methods

#### Key Topics:
- **Descriptive Statistics**: Mean, median, variance, standard deviation
- **Hypothesis Testing**: p-values, significance levels
- **Correlation and Covariance**: Relationships between variables
- **Distributions**: Understanding different types
- **Sampling**: Population vs. sample

<div class="alert alert-note">
  <h4>📌 Note: Correlation vs Causation</h4>
  <p>A fundamental principle in statistics: Correlation does not imply causation. Two variables can be correlated without one causing the other.</p>
</div>

**Key Statistical Measures:**
```
Mean: μ = Σx / n

Standard Deviation: σ = √(Σ(x-μ)² / n)

Covariance: Cov(X,Y) = E[(X-μₓ)(Y-μᵧ)]

Correlation: ρ = Cov(X,Y) / (σₓ × σᵧ)

Z-Score: z = (x - μ) / σ
```

<div class="alert alert-success">
  <h4>✅ Exam Tip: Normal Distribution</h4>
  <p>Know the 68-95-99.7 rule: 68% of data within 1σ, 95% within 2σ, 99.7% within 3σ. This is frequently tested.</p>
</div>

---

### Module 5: Optimization

#### Key Topics:
- **Gradient Descent**: First-order optimization
- **Stochastic Gradient Descent (SGD)**: Practical version
- **Convergence**: When to stop optimization
- **Learning Rates**: Hyperparameter selection
- **Momentum and Acceleration**: Advanced techniques

<div class="alert alert-tip">
  <h4>💡 Industry Tip: Optimization in Practice</h4>
  <p>In production systems, companies use advanced optimizers like Adam, RMSprop, or AdamW. These adapt the learning rate per parameter, often outperforming simple SGD. Study these implementations!</p>
</div>

**Gradient Descent Update:**
```
θ_new = θ_old - α × ∇J(θ)

where α is the learning rate and ∇J is the gradient
```

<div class="alert alert-danger">
  <h4>🔴 Common Issue: Vanishing/Exploding Gradients</h4>
  <p>Deep networks can suffer from gradients that become too small or too large. Solutions include careful initialization, batch normalization, and appropriate activation functions.</p>
</div>

---

### Module 6: Dimensionality Reduction & PCA

#### Key Topics:
- **Variance Maximization**: Projecting data to directions of maximum variance
- **Covariance Matrix & Eigen Decomposition**: Link to principal components
- **Explained Variance Ratio**: Selecting number of components
- **Whitening & Reconstruction**: Transformations and inverse mapping

**Core Equations:**
```
Given centered data matrix X ∈ ℝ^{n×d}

Covariance: Σ = (1/n) XᵀX

Eigen Decomposition: Σ vᵢ = λᵢ vᵢ
Principal Components: columns of V = [v₁, v₂, ..., v_d]
Project to k components: Z = X V_k  (V_k: top-k eigenvectors)

Explained Variance Ratio (EVR):
EVR_k = (Σ_{i=1..k} λᵢ) / (Σ_{i=1..d} λᵢ)
```

<div class="alert alert-success">
  <h4>✅ Exam Tip: Choosing k</h4>
  <p>Plot the scree curve (eigenvalues) and pick k at the elbow. Alternatively, choose the smallest k with EVR ≥ 0.95 for strong compression.</p>
</div>

<div class="alert alert-tip">
  <h4>💡 Industry Tip: PCA for Pipelines</h4>
  <p>Use PCA to reduce dimensionality before clustering or regression to stabilize models and speed up training. Standardize features before PCA.</p>
</div>

---

### Module 7: Optimization for Support Vector Machines (SVM)

#### Key Topics:
- **Primal Formulation**: Margin maximization with hinge loss
- **Dual Formulation**: Lagrange multipliers and kernels
- **KKT Conditions**: Complementary slackness and optimality
- **Kernel Trick**: Implicit feature mapping via kernels

**Primal (Soft-Margin) SVM:**
```
Given training set {(xᵢ, yᵢ)} with yᵢ ∈ {−1, +1}

min_{w,b,ξ}  (1/2)‖w‖² + C Σ ξᵢ
subject to: yᵢ (wᵀ xᵢ + b) ≥ 1 − ξᵢ,  ξᵢ ≥ 0
```

**Dual Form:**
```
max_α  Σ αᵢ − (1/2) ΣΣ αᵢ αⱼ yᵢ yⱼ K(xᵢ, xⱼ)
subject to: 0 ≤ αᵢ ≤ C,  Σ αᵢ yᵢ = 0

Decision function: f(x) = sign(Σ αᵢ yᵢ K(xᵢ, x) + b)
```

**KKT Conditions (at optimum):**
```
αᵢ ≥ 0, ξᵢ ≥ 0
αᵢ [ yᵢ (wᵀ xᵢ + b) − 1 + ξᵢ ] = 0
μᵢ ξᵢ = 0,  μᵢ ≥ 0  (for slack constraints)
```

<div class="alert alert-info">
  <h4>ℹ️ Important: Support Vectors</h4>
  <p>Only points with αᵢ > 0 contribute to the decision boundary. These are the support vectors; removing non-support vectors doesn’t change the classifier.</p>
</div>

<div class="alert alert-warning">
  <h4>⚠️ Warning: Feature Scaling</h4>
  <p>SVMs are sensitive to feature scales. Always standardize features before training to avoid dominance of high-variance features.</p>
</div>

---

## 🎯 Learning Outcomes

By the end of this course, you should be able to:

- ✅ Perform matrix operations and understand eigenvalues/eigenvectors
- ✅ Apply calculus concepts to optimization problems
- ✅ Calculate probabilities and apply Bayes' theorem
- ✅ Interpret statistical results and hypothesis tests
- ✅ Implement gradient descent optimization
- ✅ Perform PCA and reason about explained variance
- ✅ Derive SVM primal/dual and apply KKT conditions

---

## 🔬 Practice Problems

<div class="alert alert-info">
  <h4>Practice Question 1: Matrix Operations</h4>
  <p>Given matrices A (2×3) and B (3×4), what are the dimensions of AB? Can you calculate BA?</p>
</div>

<div class="alert alert-info">
  <h4>Practice Question 2: Bayes' Theorem</h4>
  <p>A disease affects 1% of population. A test is 99% accurate. If you test positive, what's the probability you actually have the disease?</p>
</div>

<div class="alert alert-info">
  <h4>Practice Question 3: Gradient Descent</h4>
  <p>Explain why a learning rate that's too high might cause gradient descent to diverge.</p>
</div>

---

## ⚡ Exam Tips

<div class="card">
  <h4>🎓 What to Focus On</h4>
  <ul>
    <li>Master the <strong>chain rule</strong> - it appears in many problems</li>
    <li>Know how to compute <strong>eigenvalues and eigenvectors</strong></li>
    <li>Understand <strong>Bayes' theorem</strong> conceptually and mathematically</li>
    <li>Be able to <strong>solve optimization problems</strong> using calculus</li>
    <li>Know the properties of common distributions (normal, exponential)</li>
  </ul>
</div>

<div class="alert alert-warning">
  <h4>⚠️ Common Exam Mistakes</h4>
  <ul>
    <li>Forgetting to multiply by chain rule derivatives</li>
    <li>Incorrect matrix dimension calculation</li>
    <li>Confusing correlation with causation in statistics</li>
    <li>Sign errors in gradient descent updates</li>
  </ul>
</div>

---

## 💼 Industry Applications

### Data Science
Probability and statistics are core to A/B testing, user segmentation, and model evaluation.

### Machine Learning
Linear algebra and calculus are essential for training neural networks and implementing algorithms.

### Finance & Economics
Optimization and probability theory drive portfolio management and risk assessment.

### Computer Vision
Linear algebra is used extensively for image transformations and deep learning models.

---

## 🔗 External Resources

### Recommended Reading
- [Linear Algebra - MIT OpenCourseWare](https://ocw.mit.edu/courses/mathematics/18-06-linear-algebra-spring-2010/)
- [3Blue1Brown: Essence of Linear Algebra](https://www.youtube.com/playlist?list=PLZHQObOWTQDPD3MizzM2xVFitgF8hE_ab)
- [3Blue1Brown: Essence of Calculus](https://www.youtube.com/playlist?list=PLZHQObOWTQDMsr28mDVmKKX8p-yc_LKiU)

### Tools & Libraries
- **NumPy**: Python library for numerical computing
- **SciPy**: Scientific computing with optimization tools
- **SymPy**: Symbolic mathematics

### Research Papers
- [Linear Algebra and Learning from Data - Gilbert Strang](https://math.mit.edu/~gs/learningfromdata/)

---

## 📋 Quick Reference Cheatsheet

### Linear Algebra
```
Vector dot product: a·b = Σ aᵢbᵢ
Matrix transpose: (AB)ᵀ = BᵀAᵀ
Trace: tr(A) = Σ aᵢᵢ (sum of diagonal)
```

### Calculus
```
Product rule: (fg)' = f'g + fg'
Quotient rule: (f/g)' = (f'g - fg') / g²
```

### Probability
```
P(A∪B) = P(A) + P(B) - P(A∩B)
P(A∩B) = P(A|B) × P(B)
```

### Statistics
```
Confidence Interval: μ ± z × (σ/√n)
t-statistic: t = (x̄ - μ) / (s/√n)
```

---

## 📞 Need Help?

- Check the [Resources page]({{ site.baseurl }}/resources/) for additional learning materials
- Review the practice problems and solutions
- Consult the external resource links provided above

**Last Updated**: December 2025
