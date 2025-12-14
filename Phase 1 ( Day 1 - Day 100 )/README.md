# 🚀 PHASE 1 
## 📘 Day 01 — Vectors & Dot Product Fundamentals
Building AI From First Principles — One Day at a Time

Welcome to Day 1 of my 1000 Days of AI/ML Mastery.
Phase 1 is all about foundations, but not by reading theory —
👉 I will build the foundations myself from scratch.

Today marks the beginning of implementing a mini-NumPy, a math engine that will later power neural networks, optimizers, attention layers, and full deep learning frameworks.

---

### 🔥 What I Learned Today
- What a vector really represents (geometry, magnitude, direction)
- Why the dot product measures alignment between vectors
(positive = same direction, negative = opposite, 0 = orthogonal)
- Scalar vs vector intuition
- Importance of vector operations in machine learning
(embeddings, gradients, projection, similarity, etc.) 

### 🔍 Deeper Understanding
- Vectors are not just lists of numbers — they are arrows that capture both magnitude and direction, which makes them perfect for representing anything in machine learning that has structure or meaning.
- The dot product becomes powerful because it tells you how much one vector “points in the direction” of another, which is exactly why it can measure similarity, alignment, or influence. When the dot product is positive, the vectors reinforce each other; when negative, they oppose each other; and when zero, they share nothing in common — this is the geometric basis of orthogonality.
- In machine learning, this concept shows up everywhere: embeddings use dot products to measure similarity, gradients use them to update weights, and attention mechanisms in Transformers rely on them to decide which tokens matter to each other. 
- Thinking in vectors helps you visualize models as systems moving through high-dimensional space, not just crunching numbers. Once this intuition becomes second nature, understanding deeper concepts like projections, cosine similarity, and attention becomes effortless

---
### 🛠️ What I Built Today

#### 📁 File
**Directory:** `foundations/math/`  
**File:** `vector.py` (example)

#### 🔧 Implemented Functions

- `dot(a, b)`
- `add(a, b)`
- `sub(a, b)`
- `scale(a, α)`


###### ➡️ This is the first building block for matrix multiplication, neural networks, and gradients.

#### 🧪 Experiments

- Tested dot product with different vector orientations
- Verified geometric interpretation using angle formula
- Created a small notebook to plot 2D vectors and visualize dot product sign

Screenshot of notebook added to:

experiments/day1_vector_experiments.ipynb

#### 🎯 Plan for Tomorrow

Implement vector operations:

- scalar multiply
- vector subtraction
- magnitude + normalization
- Finish complete Vector API

Start implementing Matrix class on Day 4

#### 🌅 Daily Reflection

Today sets the foundation for the next 1000 days.
A simple vector is the seed from which LLMs, Transformers, and GPUs grow.
Building from first principles is the only way to become a true AI engineer.


## 📘 Day 02 — Vector Magnitude Unit vectors & Normalization


### 🔥 What I Learned Today
✅ 1. Vector Magnitude = The “length” of information
The magnitude tells how “large” a vector is — not just in geometry, but in meaning.
For embeddings, it relates to how strong or expressive a feature is.

✅ 2. Normalization = Keeping vectors comparable
Turning a vector into a unit vector keeps direction but removes scale.
This is essential in ML because many algorithms depend only on direction, not raw values.

✅ 3. Why unit vectors dominate ML
Unit vectors make:
- cosine similarity meaningful
- training more stable
- embeddings comparable across datasets
- attention scores easier to interpret

✅ 4. Clipping, scaling & numerical stability

I learned that normalization must avoid division by zero → an important detail for stable deep learning systems (e.g., layer normalization, RMSNorm).

### 🔍 Deeper Understanding
🧭 Magnitude as energy
I started visualizing magnitude not just as length but as energy contained in a vector — useful for thinking about gradients.
A large gradient vector means “high corrective energy,” while a normalized gradient means “controlled, stable learning.”

🔦 Why normalization matters for embeddings
If two embedding vectors have different magnitudes, the dot product mixes up similarity with raw strength.
But after normalization:
similarity = pure direction comparison

This geometric purity is what powers cosine similarity, semantic search, LLM attention, and contrastive learning (CLIP, SimCLR, DINO, etc.).

🎯 Direction > magnitude in high-dimensional ML
Neural networks often care more about the orientation of a vector than its size.
This intuition is key to understanding:

- how Transformer attention picks important tokens
- how word embeddings capture meaning
- why norm-based regularization stabilizes training
When I saw this geometrically, everything felt much clearer.

---
### 🛠️ What I Built Today
#### 📁 File
**Directory:** `foundation/math/vector.py`- extended with full vector operations.
**File:** `vector.py` 

#### 🔧 Implemented Functions

- `magnitude(a)`
- `normalize(a)`
- `distance(a, b)`
- `hadamard(a, b)`  # elementwise multiply
- `scale(a, α)`     # refined version with type checks



       
          

💡 Important Notes in Implementation

- normalization handles near-zero vectors safely
- magnitude uses stable √(Σ x²) computation
- all operations enforce same-length inputs
- clean error messages → useful for debugging ML code later


#### 🧪 Experiments

🧹 1. Normalization tests
Verified that every normalized vector has magnitude ≈ 1.0
Checked edge cases:
- zero vector
- extremely small values
- extremely large values

📐 2. Distance vs dot product
Plotted pairs of vectors on a 2D grid:
- small angles → small distance
- orthogonal vectors → distance larger but dot product = 0
Great intuition for similarity metrics.

🎨 3. Visual exploration notebook

It includes:
- rendering random vectors
- showing magnitude
- overlaying unit vectors
- coloring vectors based on dot product sign

This visual grounding is helping me feel vector math instead of just knowing formulas.

#### 🎯 Plan for Tomorrow
Tomorrow will complete the Vector module and connect it to early neural-network mechanics.

Goals for Day 3
- implement projection of one vector onto another
- cosine similarity from scratch
- angle between vectors
- deeper geometric experiments
- start preparing the API surface for the upcoming Matrix class

This will complete the full Vector API, making it ready for:
matrix multiplication, forward passes, backprop, optimizers, embeddings, and attention scoring.

#### 🌅 Daily Reflection

Today felt like unlocking a piece of the geometric engine inside every neural network.
Vectors aren’t just arrays — they’re geometry encoded as numbers.
Magnitude gives them weight; normalization gives them identity.
Understanding this at a deep level means the math behind neural networks stops feeling abstract and starts feeling alive.

These fundamentals aren’t glamorous, but they are the foundation on which entire AI systems stand.
Day 2 is done — and the base of my mini-NumPy engine is starting to take shape.


## 📘 Day 03 — Matrix Foundations, Shapes & Linear Algebra Core


### 🔥 What I Learned Today
✅ 1. A Matrix is just a collection of aligned vectors
Rows must have equal length — this enforcement is the bedrock of linear algebra.
I finally understood that shape is the first contract that makes every ML operation possible.

✅ 2. Why matrices matter in machine learning
Matrices represent:
- weights in neural networks
- batches of embeddings
- transformation operators
- attention score maps
- convolution lowering (im2col)
Everything deep learning does is basically matrix operations at scale.

✅ 3. Matrix multiplication = combining directions
- A * B is not just loops — it's:
- projecting rows of A
- onto columns of B
- and building new geometry
This geometric interpretation reveals why linear layers, transformers, and even CNNs rely on the same primitive.

✅ 4. Transpose is more important than I thought
Transposing flips:
- row vectors → column vectors
- column vectors → row vectors
- Attention, backprop, similarity search… all rely heavily on fast, clean transposes.

### 🔍 Deeper Understanding
🧭 Matrix as a transformation machine
A matrix turns an input vector into a transformed vector:
scale → rotate → shift → distort → embed → classify.
Seeing matrices as operators instead of just nested arrays changed how I think about forward passes.

🔦 Why shape correctness is critical
Every ML failure — exploding gradients, invalid losses, NaN propagation — often starts with shape mismatch.
Now I enforce:
- consistent row sizes
- compatible dimensions for multiplication
- clear, helpful error messages
This is identical to how PyTorch/NumPy do internal validation.

🎯 Matrix multiplication ≠ elementwise multiply
Elementwise = Hadamard
Matrix multiply = Linear transformation

This distinction becomes crucial when:
- building embeddings
- computing attention
- implementing backprop

Understanding both at a geometric level gave me clarity.
---
### 🛠️ What I Built Today
#### 📁 File
**Directory:** `foundation/math/matrix.py`
**File:** `matrix.py` 

#### 🔧 Implemented Functions

- `magnitude(a)`
- `shape()`
- `add(A, B)`
- `sub(A, B)`
- `scale(A, α)`
- `hadamard(A, B)`
- `transpose(A)`
- `matvec(A, v)` — matrix × vector
- `matmul(A, B)` — matrix × matrix


💡 Important Notes in Implementation

- strict 2D shape checks for safety
- type coercion to float for numerical consistency
- matrix-vector multiply uses dot products row-wise
- matrix-matrix multiply uses transpose trick for cleaner implementation
- clean, NumPy-like error messages for debugging
- zero dependency, pure Python implementation — educational & transparent


#### 🧪 Experiments


🧩 1. Verified shapes across all operations
Tested:
- correct alignment
- mismatched sizes
- rectangular matrices
- multiplication shape rules

This helped solidify the mental model for (m×n) · (n×p) → (m×p).

📐 2. Visualizing matrix → vector transformations
Plotted simple 2D vectors under various matrices:
- scaling
- rotation
- shear

This made matrix multiplication feel intuitive rather than symbolic.

🔗 3. Compared matrix multiplication vs Hadamard
Saw clearly how:
- Hadamard = filters features
- Matmul = remaps features
A crucial insight for understanding deep learning architecture internals.

📊 4. Benchmarked naive matmul
Measured time complexity and confirmed the O(n³) cost of the pure Python version — great context for why BLAS, CUDA, and Tensor Cores matter.

🎯 Plan for Tomorrow
Day 4 Goals
- implement matrix norms
- row/column slicing
- outer product
- broadcast engine (mini-NumPy style)
- prepare API for backprop & neural network layers
This will push the project closer to a fully working “micro-NumPy” core with clean vector + matrix interop.

🌅 Daily Reflection
Today felt like I unlocked the transformation engine behind neural networks.
Matrices aren't storage — they are machines that transform geometry.
Understanding shapes, transposes, and multiplication gave me the mental model to build linear layers, attention, gradients, and optimization from scratch.
Slow steps, but foundational steps.

Day 3 complete — and the heart of my mini-NumPy engine is now beating.


## 📘 Day 04 — Matrix Norms, Slicing, Outer Products & Broadcasting Engine


### 🔥 What I Learned Today


✅ 1. Matrix norms are the “size” of transformations
Just like vector magnitude measures energy, matrix norms measure:
- total transformation strength
- stability of neural networks
- gradient explosion risk
I implemented Frobenius Norm, the matrix equivalent of vector magnitude.

✅ 2. Row/column slicing = reading structure
Neural networks access:
- each row as a neuron
- each column as feature dimension
Understanding clean slicing makes linear algebra intuitive and prepares the architecture for batched operations.

✅ 3. Outer product = building matrices from vectors
Outer product forms the basis of:
- attention score matrices
- covariance matrices
- weight updates in gradient descent
- rank-1 approximations

It is literally:
geometry × geometry = transformation

✅ 4. Broadcasting = the secret sauce of NumPy
Broadcasting rules:
- align shapes from the right
- expand dimensions of size 1
- operations apply across expanded dimensions
  
I built a simplified broadcasting engine that supports:
- matrix + scalar
- matrix + row vector
- matrix + column vector
- matrix + matrix (same or broadcastable shapes)

This small feature unlocks 70% of NumPy’s magic.

### 🔍 Deeper Understanding

🧭 Frobenius norm as transformation power
I learned that Frobenius norm approximates how much a matrix can stretch space.
- High norm → unstable gradients
- Low norm → smoother training

🔦 Why slicing matters
I now think of matrices as:
- rows = samples
- columns = features
This intuition becomes crucial when building:
- dense layers
- embeddings
- loss functions
- statistical preprocessing

🎯 Broadcasting = fewer loops, more math
Transformers rely heavily on broadcasting for:
- positional encodings
- attention score scaling
- mask expansion
- batch operations

My tiny broadcasting system is now good enough to support future neural-network layers.
---

### 🛠️ What I Built Today
#### 📁 File
**Directory:** `foundation/math/matrix.py`
**File:** `vector.py` (extended)
**File:** `matrix.py` (added features)


#### 🧪 Experiments

1. Norm stability tests
Verified numeric stability using:
- tiny values
- huge values
- random matrices

2. Slicing visualizations

- Plotted each row as a separate vector.
- Saw how features separate by columns.
- Very helpful for visualizing embeddings.

3. Outer product intuition tests

Generated:
- key × query
- noise × noise
- feature × weight
Saw how outer products form structured rank-1 matrices.

4. Broadcasting correctness
Tested:
- scalar + matrix
- matrix + row-vector
- matrix + column-vector
- incompatible shapes (error raised correctly)

🎯 Plan for Tomorrow
- build a full Dense Layer (weights, bias, forward)
- implement activation functions (ReLU, sigmoid, tanh)
- design a tiny autograd engine
- set up a mini backprop pipeline
- start preparing for optimizers (SGD)
This will mark the transition from pure math → real neural-network components.

🌅 Daily Reflection

Today I built the mathematical machinery behind real deep-learning pipelines.
Matrix norms taught me how networks stay stable, slicing revealed structure within data, outer products showed how attention scores are formed, and broadcasting unlocked vectorized computation.

Each feature felt like adding a new muscle to my mini-NumPy engine — stronger, more flexible, and ready for neural network layers.

Day 4 done — and the micro-NumPy engine is starting to feel alive.

## 📘 Day 05 — micro-NumPy Engine 

Welcome to **Day 5** of building a tiny deep-learning engine from scratch — a miniature NumPy + Autograd + Neural Network core, built line-by-line in pure Python.

---

## 🎯 Goals for Today

- Build a fully functional **Dense Layer (Linear layer)**  
- Implement activation functions:  
  - ReLU  
  - Sigmoid  
  - Tanh  
- Design a minimal but complete **autograd engine**  
- Assemble a **backprop pipeline**  
- Prepare the base for upcoming **optimizers (SGD)**  

With these pieces, the project moves from “math operations” → “neural network foundations”.

---

## 🧠 What Was Built Today

### ✔ Dense Layer  
A fully trainable layer with:
- weight matrix  
- bias vector  
- forward computation using matrix multiplication + broadcasting  

### ✔ Activation Functions  
All are differentiable and implement their own backward rules:
- **ReLU**
- **Sigmoid**
- **Tanh**

### ✔ Autograd Engine  
A tiny version of PyTorch's reverse-mode autodiff:
- Builds a dynamic computation graph
- Stores parents + `_backward()` closures
- Performs depth-first backpropagation

---

## 🏗 Code Structure
├── engine/<br>
│ ├── tensor.py<br>
│ ├── ops.py<br>
│ ├── autograd.py<br>
│ └── layers.py<br>

📌 Plans for tomorrow

- Implement SGD optimizer
- Add loss functions (MSE, BCE)
- Build Sequential model wrapper
- Train the first real model (XOR dataset)
- Begin modularizing API for user-friendly use

🌅 Daily Reflection

Today marked the shift from raw mathematical ops into actual deep learning structures.
Building Dense layers felt like assembling the skeletal frame of neural networks. Activations added life, and autograd became the nervous system.

Every piece clicked together — and the engine started feeling like a functioning micro-framework.

Day 5 complete — the tiny neural network core is born.

## 📘 Day 06 — micronumpy - Optimizers, Losses, Sequential & XOR Training

Welcome to Day 6 of building a tiny deep-learning framework from scratch — a micro-NumPy + micro-Autograd engine in pure Python.

Today marks the transition from just computing gradients → to actually training models.
This is the moment where the math becomes a machine.

🎯 Goals for Today
✔ Implement an Optimizer
- Added SGD with learning rate + optional momentum placeholder
- Connected optimizer to trainable Tensor parameters

✔ Add Loss Functions
- MSELoss — for regression & XOR
- BCELoss (simple) — for binary classification

✔ Build a Modular Neural-Network API
- Dense layer now supports trainability
- Sequential container to stack layers like Keras / PyTorch

✔ Write First Training Script
- Trained a 2-layer network to solve the XOR problem

### 🧠 What I Learned Today
🔥 1. How models actually learn

Today’s biggest insight:
Backpropagation alone does nothing unless an optimizer updates parameters.
SGD connected the gradient engine with the learning loop:

`param = param - lr * grad`

That single line transforms gradients into intelligence.

🔥 2. Why loss functions define learning direction
A loss is not just an error measurement — it is the source of the gradient signal.
- MSE teaches networks to reduce squared error.
- BCE pushes probabilities toward the correct class.
Changing the loss = changing the behavior of the learning system.

🔥 3. Sequential design shapes usability
The Sequential class made training much more readable:

`
model = Sequential(
    Dense(2, 4),
    Tanh(),
    Dense(4, 1),
    Sigmoid()
)
`<br>

🔥 4. XOR is the “Hello World” of Neural Networks

XOR proves your framework supports:
- Multi-layer nonlinear networks
- Backprop through multiple layers
- Parameter updates
- Stable training dynamics
It’s small, but it’s a real milestone.

### 🛠️ What I Built Today

✔ 1. SGD Optimizer
- Iterates through model parameters
- Applies gradient descent step
- Resets gradients after update
- Simple, clean, framework-friendly

✔ 2. losses.py
Included:
- mse(pred, target)
- bce(pred, target) (simple numerical stability)

✔ 3. nn/sequential.py
A small container that:
- Stores layers
- Automatically passes output to next layer
- Aggregates parameters cleanly

✔ 4. examples/xor_train.py

A fully working training loop:
- forward pass
- loss compute
- backward pass
- optimizer step
- prints loss every epoch
- solves XOR in < 2000 iterations

### 🧪 Experiments
#### 🧩 XOR Learning

Network:
Input → Dense(2→4) → Tanh → Dense(4→1) → Sigmoid

Results:
- Loss drops smoothly
- Model predicts XOR correctly
- Verified gradients are flowing end-to-end
- Observed sigmoid output converging toward {0,1}

🧮 Gradient Sanity Tests
- Compared manual gradients for MSE with autograd outputs
- Verified parameter update magnitudes decrease when learning rate is lowered

🔍 Hyperparameter Experiments
- Tried learning rates {0.1, 0.01, 0.001}
- Observed divergence at 0.5 → great intuition builder
- Saw slow learning at 0.001
- These experiments helped understand training stability.


### 📁 File Structure (Day 6)<br>
micronumpy/<br>
├── engine/<br>
│   ├── __init__.py<br>
│   ├── tensor.py<br>
│   ├── ops.py<br>
│   └── activations.py<br>
├── nn/<br>
│   ├── __init__.py<br>
│   └── layers.py<br>
├── training/<br>
│   ├── __init__.py<br>
│   ├── losses.py<br>
│   └── optim.py<br>
├── examples/<br>
│   └── xor_train.py<br>

### 📌 Plans for Tomorrow (Day 7)
🔥 Big focus: Training Infrastructure + More Layers
Tomorrow’s goals:

✔ Add More Optimizers
- SGD + Momentum
- RMSProp (maybe)
- Adam (if possible)

✔ Implement More Losses
- Softmax + Cross-Entropy
- Multi-class classification

✔ Add More Layers
- Dropout
- Flatten
- Softmax layer
- Possibly Conv2D placeholders

✔ Build a Minimal Trainer API

Something like:
- trainer = Trainer(model, optimizer, loss)
- trainer.fit(X, y, epochs=...)

✔ Build a toy dataset loader
- Spiral dataset
- Linear separable dataset
- XOR multi-batch version

### 🌅 Daily Reflection

Today felt like breathing life into the framework.
Until now we had:
- math
- tensors
- autograd
- layers
But today—the model learned.

Watching the loss drop and the XOR truth table go from random to correct was surreal.
It wasn’t NumPy.
It wasn’t PyTorch.
It was my own code, piece by piece.

Small engine.
Real learning.
Huge milestone.

Day 6 done — and the micro-NumPy engine just trained its first neural network.
The foundation for a real tiny deep-learning library is now alive.



## 📘 Day 07 — micronumpy - Training Infrastructure, Optimizers & Data Pipelines

Day 7 pushes the micro-NumPy engine from basic training loops into a real training framework.

Today was about infrastructure — the systems that make deep learning scalable, reusable, and elegant.

🎯 Goals for Today
✔ Advanced optimizers
✔ Multi-class losses
✔ More neural layers
✔ Unified training API
✔ Dataset loaders


🧠 What I Learned Today

🔥 1. Optimizers shape learning behavior
- SGD is just the beginning.
- Momentum smooths gradients
- RMSProp adapts learning rates
- Adam balances speed + stability
- Each optimizer encodes a philosophy of learning.

🔥 2. Training APIs matter as much as math
Separating:
- model
- optimizer
- loss
- data
- makes experimentation fast and readable.

🔥 3. Data pipelines are part of the model
The dataset loader controls:
- batch structure
- distribution
- difficulty
Bad data → bad learning, no matter how good the math is.


🛠️ What I Built Today
✔ Optimizers
- SGD + Momentum
- RMSProp
- Adam

✔ New Layers
- Dropout
- Flatten (future-ready)
- Softmax

✔ Losses
- Softmax + Cross-Entropy

✔ Trainer API
- trainer = Trainer(model, optimizer, loss)
- trainer.fit(X, y, epochs=1000)

✔ Dataset Loader
- XOR (multi-batch)
- Spiral dataset
- Linear-style placeholders


📁 Updated Project Structure
<br>
micro_numpy/ <br>
├── engine/ <br>
├── nn/ <br>
│   ├── advanced_layers.py <br>
├── optim/ <br>
│   ├── momentum.py <br>
│   ├── rmsprop.py <br>
│   ├── adam.py <br>
├── losses/ <br>
│   ├── softmax_ce.py <br>
├── data/ <br>
│   ├── datasets.py <br>
├── trainer/ <br>
│   ├── trainer.py <br>


🧪 Experiments
- Trained XOR using Adam
- Compared SGD vs Momentum
- Observed faster convergence with Adam
- Validated Trainer API abstraction


📌 Plans for Tomorrow (Day 8)
- Convolution layers (Conv1D/Conv2D skeleton)
- Batch Normalization
- Weight initialization strategies
- Model saving/loading
- Evaluation metrics


🌅 Daily Reflection

Today I didn’t just train models —
I built the system that trains models.

This is where deep learning stops being a script and starts being an engine.

Day 7 complete — and micro-NumPy now feels like a real framework.



### 📘 Day 08 — micronumpy: Convolutions, Normalization & Model Infrastructure

Day 8 marks the transition from basic neural networks to deep-learning systems engineering.

Today wasn’t about training accuracy —
it was about building the machinery that real frameworks rely on.

#### 🎯 Goals for Today

- ✔ Convolution layer foundations
- ✔ Batch Normalization
- ✔ Weight initialization strategies
- ✔ Model saving/loading
- ✔ Evaluation metrics

#### 🧠 What I Learned Today
🔥 1. Convolutions are structured dot products

A convolution is not magic.
It is:
- sliding windows
- shared weights
- local geometry
Understanding this makes CNNs feel mechanical instead of mysterious.

🔥 2. Normalization controls training physics

BatchNorm:
- stabilizes gradients
- smooths loss surfaces
- accelerates convergence
It is a control system, not just math.

🔥 3. Initialization decides if learning even starts

Bad initialization → dead networks.
Good initialization:
- preserves variance
- prevents exploding/vanishing gradients
- Xavier & He are engineering solutions, not theory tricks.

🔥 4. Saving models = freezing intelligence
Persistence turns experiments into assets.
Without save/load:
- no deployment
- no reproducibility
- no real systems

🛠️ What I Built Today

✔ Convolution Layers
- Conv1D (forward)
- Conv2D (forward skeleton)
- Backward hooks ready

✔ Batch Normalization
- Mean/variance normalization
- Learnable scale & shift

✔ Weight Initialization
- Zeros
- Random uniform
- Xavier
- He initialization

✔ Model Persistence
- save_model(model, "model.pkl")
- model = load_model("model.pkl")

✔ Evaluation Metrics
- Accuracy
- MSE

📁 Updated Project Structure
micro_numpy/ <br>
├── nn/<br>
│   ├── conv.py<br>
│   ├── batchnorm.py<br>
│   ├── init.py<br>
├── utils/<br>
│   ├── save_load.py<br>
│   ├── metrics.py<br>
└── examples/<br>
    ├── conv_sanity.py<br>

🧪 Experiments

- Verified Conv1D sliding behavior
- Tested BatchNorm output stability
- Compared Xavier vs random init variance
- Saved and restored trained models
- Computed accuracy + MSE

📌 Plans for Tomorrow (Day 9)

- Backprop for Conv layers
- BatchNorm backward pass
- Gradient checking
- Numerical stability tests
- Performance profiling

🌅 Daily Reflection

Today felt like building the industrial tools of deep learning.

- Convolutions taught me spatial reasoning.
- Normalization taught me control theory.
- Initialization taught me that learning is fragile.
- Persistence taught me that systems matter more than scripts.

Day 8 complete —
and micro-NumPy is no longer a toy.
It’s becoming an engine.
