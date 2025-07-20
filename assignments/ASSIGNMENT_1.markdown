<script src="https://rawcdn.githack.com/oscarmorrison/md-page/master/md-page.js"></script><noscript>
# Quantum Computing Assignment 1 - Solutions

## 1. Differentiate between Digital Computer and Quantum Computer

| Aspect | Digital Computer | Quantum Computer |
|--------|-----------------|------------------|
| **Basic Unit** | Bit (0 or 1) | Qubit (superposition of 0 and 1) |
| **States** | Definite states only | Superposition of multiple states |
| **Processing** | Sequential/Parallel classical operations | Quantum operations on superposed states |
| **Memory** | Classical memory bits | Quantum states in Hilbert space |
| **Logic Gates** | Boolean logic gates (AND, OR, NOT) | Quantum gates (Hadamard, Pauli, CNOT) |
| **Error Handling** | Classical error correction | Quantum error correction required |
| **Algorithms** | Classical algorithms | Quantum algorithms (Shor's, Grover's) |
| **Measurement** | Direct state reading | Probabilistic measurement collapse |
| **Entanglement** | No entanglement | Quantum entanglement possible |
| **Speed** | Limited by classical physics | Exponential speedup for certain problems |

## 2. How quantum information is used in quantum computing?

Quantum information is the fundamental resource in quantum computing that leverages quantum mechanical properties:

- **Superposition**: Qubits can exist in multiple states simultaneously, allowing parallel computation
- **Entanglement**: Creates correlations between qubits that don't exist classically
- **Interference**: Quantum amplitudes can interfere constructively or destructively
- **Information Storage**: Each qubit can store exponentially more information than classical bits
- **Quantum Algorithms**: Information is processed using quantum gates that manipulate probability amplitudes
- **Measurement**: Information is extracted through probabilistic measurements that collapse quantum states

## 3. What is Shannon Entropy?

Shannon Entropy is a measure of information content or uncertainty in a system:

**Formula**: 
$$H(X) = - \sum_{x} p(x) \log_2 p(x)$$

Where:
- $H(X)$ = Shannon entropy
- $p(x)$ = probability of outcome $x$
- $\sum$ means sum over all possible outcomes $x$

**Properties**:
- Measured in bits (when using $\log_2$)
- Higher entropy = more uncertainty/information
- Maximum entropy occurs when all outcomes are equally probable
- Minimum entropy (0) occurs when outcome is certain

**Example**: For a fair coin flip:
$$H = -\frac{1}{2}\log_2\left(\frac{1}{2}\right) - \frac{1}{2}\log_2\left(\frac{1}{2}\right) = 1 \text{ bit}$$

## 4. What is a qubit and how does it differ from a classical bit?

**Classical Bit**:
- Can only be in state 0 OR 1
- Definite, measurable state
- No uncertainty in state

**Qubit (Quantum Bit)**:
- Can be in superposition of 0 AND 1 simultaneously
- Described by probability amplitudes
- Measurement gives probabilistic outcomes
- Can be entangled with other qubits
- Exists in complex vector space

**Key Differences**:
1. **States**: Bit has 2 states, qubit has infinite possible states
2. **Measurement**: Bit gives deterministic result, qubit gives probabilistic result
3. **Information**: Qubit can encode exponentially more information
4. **Operations**: Quantum operations are reversible, classical may not be

## 5. Write the general mathematical form of a qubit

The general mathematical form of a qubit is:

$$|\psi\rangle = \alpha|0\rangle + \beta|1\rangle$$

Where:
- $|\psi\rangle$ = qubit state (ket notation)
- $\alpha, \beta$ = complex probability amplitudes
- $|0\rangle, |1\rangle$ = computational basis states
- **Normalization condition**: $|\alpha|^2 + |\beta|^2 = 1$

**Matrix representation**:
$$|\psi\rangle = \alpha \begin{pmatrix} 1 \\ 0 \end{pmatrix} + \beta \begin{pmatrix} 0 \\ 1 \end{pmatrix} = \begin{pmatrix} \alpha \\ \beta \end{pmatrix}$$

**Physical interpretation**:
- $|\alpha|^2$ = probability of measuring 0
- $|\beta|^2$ = probability of measuring 1

## 6. Explain the concept of measurement in qubits. What happens after a measurement?

**Before Measurement**:
- Qubit exists in superposition: 
$$|\psi\rangle = \alpha|0\rangle + \beta|1\rangle$$
- State is probabilistic

**During Measurement**:
- Measurement operator is applied
- System interacts with measuring device

**After Measurement**:
- **State collapse**: Superposition is destroyed
- **Probabilistic outcome**: Get $|0\rangle$ with probability $|\alpha|^2$ or $|1\rangle$ with probability $|\beta|^2$
- **New state**: Becomes either $|0\rangle$ or $|1\rangle$ (definite state)
- **Irreversible process**: Cannot recover original superposition
- **Born rule**: Probabilities given by squared amplitudes

**Example**:
$$\text{If } |\psi\rangle = \frac{1}{\sqrt{2}}|0\rangle + \frac{1}{\sqrt{2}}|1\rangle$$
- 50% chance of measuring 0 → state becomes $|0\rangle$
- 50% chance of measuring 1 → state becomes $|1\rangle$

## 7. What is the Bloch sphere and how does it represent a qubit?

The **Bloch sphere** is a geometric representation of qubit states as points on a unit sphere.

**Mathematical representation**:
$$|\psi\rangle = \cos\left(\frac{\theta}{2}\right)|0\rangle + e^{i\phi} \sin\left(\frac{\theta}{2}\right)|1\rangle$$

Where:
- $\theta$ = polar angle (0 to $\pi$)
- $\phi$ = azimuthal angle (0 to $2\pi$)

**Key points on Bloch sphere**:
- **North pole**: $|0\rangle$ state
- **South pole**: $|1\rangle$ state  
- **Equator**: Superposition states
- **Any point**: Valid qubit state

**Properties**:
- Radius = 1 (normalization)
- Antipodal points are orthogonal
- Pure states on surface, mixed states inside
- All quantum operations are rotations

## 8. What is the Hilbert space dimension of a system of n qubits?

**Single qubit**: Dimension = 2

**n qubits**: Dimension = $2^n$

**Examples**:
- 1 qubit: $2^1 = 2$ dimensions
- 2 qubits: $2^2 = 4$ dimensions  
- 3 qubits: $2^3 = 8$ dimensions
- n qubits: $2^n$ dimensions

**Basis states for n qubits**:
$$\{|00...0\rangle, |00...1\rangle, |01...0\rangle, ..., |11...1\rangle\}$$

**General state**:
$$|\psi\rangle = \sum_{i=0}^{2^n-1} \alpha_i|i\rangle$$

Where $\sum |\alpha_i|^2 = 1$

## 9. Explain the tensor product and how it applies to multiple qubits

**Tensor Product ($\otimes$)**:
Mathematical operation for combining quantum systems.

**For two qubits**:

If $|\psi_1\rangle = \alpha|0\rangle + \beta|1\rangle$ and $|\psi_2\rangle = \gamma|0\rangle + \delta|1\rangle$

Then: 
$$|\psi_1\rangle \otimes |\psi_2\rangle = \alpha\gamma|00\rangle + \alpha\delta|01\rangle + \beta\gamma|10\rangle + \beta\delta|11\rangle$$

**Matrix form**:

If $|\psi_1\rangle = \begin{pmatrix} \alpha \\ \beta \end{pmatrix}$ and $|\psi_2\rangle = \begin{pmatrix} \gamma \\ \delta \end{pmatrix}$

Then: $|\psi_1\rangle \otimes |\psi_2\rangle = \begin{pmatrix} \alpha\gamma \\ \alpha\delta \\ \beta\gamma \\ \beta\delta \end{pmatrix}$

**Properties**:
- Creates composite quantum systems
- Dimension multiplies: $\dim(H_1 \otimes H_2) = \dim(H_1) \times \dim(H_2)$
- Not commutative in general
- Essential for multi-qubit systems

## 10. Define a vector space in the context of quantum computing

A **vector space** $V$ over field $F$ (usually complex numbers $\mathbb{C}$) is a set with two operations:

**Operations**:
1. **Vector addition**: $u + v \in V$ for all $u,v \in V$
2. **Scalar multiplication**: $\alpha v \in V$ for all $\alpha \in F, v \in V$

**In quantum computing**:
- Quantum states are vectors in complex vector space
- Basis states span the space
- Linear combinations represent superposition
- Complex coefficients are probability amplitudes

**Example**: 2-dimensional complex vector space for single qubit
$$V = \{\alpha|0\rangle + \beta|1\rangle : \alpha,\beta \in \mathbb{C}, |\alpha|^2 + |\beta|^2 = 1\}$$

## 11. What are the axioms of a vector space?

**Addition Axioms**:
1. **Closure**: $u + v \in V$ for all $u,v \in V$
2. **Associativity**: $(u + v) + w = u + (v + w)$
3. **Commutativity**: $u + v = v + u$
4. **Identity**: $\exists \mathbf{0} \in V$ such that $v + \mathbf{0} = v$ for all $v \in V$
5. **Inverse**: For each $v \in V$, $\exists (-v) \in V$ such that $v + (-v) = \mathbf{0}$

**Scalar Multiplication Axioms**:
6. **Closure**: $\alpha v \in V$ for all $\alpha \in F, v \in V$
7. **Distributivity**: $\alpha(u + v) = \alpha u + \alpha v$
8. **Distributivity**: $(\alpha + \beta)v = \alpha v + \beta v$
9. **Associativity**: $\alpha(\beta v) = (\alpha\beta)v$
10. **Identity**: $1v = v$ for all $v \in V$

## 12. What is meant by a linear combination of quantum states?

A **linear combination** is a sum of quantum states multiplied by complex coefficients:

**General form**:
$$|\psi\rangle = c_1|\psi_1\rangle + c_2|\psi_2\rangle + ... + c_n|\psi_n\rangle$$

Where:
- $c_i \in \mathbb{C}$ (complex coefficients)
- $|\psi_i\rangle$ are quantum states
- For normalized states: $\sum |c_i|^2 = 1$

**Examples**:
1. **Superposition**: 
   $$|\psi\rangle = \frac{1}{\sqrt{2}}|0\rangle + \frac{1}{\sqrt{2}}|1\rangle$$

2. **Bell state**: 
   $$|\psi\rangle = \frac{1}{\sqrt{2}}|00\rangle + \frac{1}{\sqrt{2}}|11\rangle$$

3. **General 2-qubit**: 
   $$|\psi\rangle = \alpha|00\rangle + \beta|01\rangle + \gamma|10\rangle + \delta|11\rangle$$

**Physical meaning**: Represents quantum superposition where system exists in multiple states simultaneously.

## 13. Define a Hilbert space. What are its essential properties?

A **Hilbert space** $H$ is a complete inner product space.

**Essential Properties**:

1. **Vector space**: Satisfies all vector space axioms
2. **Inner product**: $\langle u,v\rangle : H \times H \to \mathbb{C}$ with properties:
   - Conjugate symmetry: $\langle u,v\rangle = \langle v,u\rangle^*$
   - Linearity: $\langle \alpha u + \beta v, w\rangle = \alpha\langle u,w\rangle + \beta\langle v,w\rangle$
   - Positive definiteness: $\langle v,v\rangle \geq 0$, equality iff $v = 0$
3. **Norm**: $\|v\| = \sqrt{\langle v,v\rangle}$
4. **Completeness**: Every Cauchy sequence converges
5. **Separability**: Has countable dense subset

**In quantum computing**:
- State space of quantum system
- Enables probability calculations
- Foundation for quantum mechanics mathematics

## 14. What is a spanning set in a vector space?

A **spanning set** $S$ of vector space $V$ is a set of vectors such that every vector in $V$ can be written as a linear combination of vectors in $S$.

**Definition**: $S$ spans $V$ if:
$$\text{For any } v \in V, \exists \text{ scalars } c_1, c_2, ..., c_n \text{ such that:}$$
$$v = c_1s_1 + c_2s_2 + ... + c_ns_n \text{ where } s_i \in S$$

**Example for qubits**:
- $S = \{|0\rangle, |1\rangle\}$ spans single qubit space
- Any qubit $|\psi\rangle = \alpha|0\rangle + \beta|1\rangle$
- Computational basis states span the space

**Properties**:
- $\text{span}(S) = V$ means $S$ spans $V$
- Minimal spanning set is a basis
- Can have redundant vectors

## 15. Explain why the spanning set of a vector space is not unique

**Reasons for non-uniqueness**:

1. **Redundant vectors**: Can add linearly dependent vectors
   - $\{|0\rangle, |1\rangle\}$ and $\{|0\rangle, |1\rangle, |0\rangle + |1\rangle\}$ both span qubit space

2. **Different bases**: Multiple basis choices
   - Computational basis: $\{|0\rangle, |1\rangle\}$
   - Hadamard basis: $\{|+\rangle, |-\rangle\}$ where 
     $$|+\rangle = \frac{|0\rangle + |1\rangle}{\sqrt{2}}, \quad |-\rangle = \frac{|0\rangle - |1\rangle}{\sqrt{2}}$$

3. **Linear independence**: Any linearly independent set can be extended
   - Start with $\{|0\rangle\}$, add any non-parallel vector like $|1\rangle$

4. **Size variation**: Spanning sets can have different sizes
   - Minimal: basis (dimension = size)
   - Non-minimal: includes extra vectors

**Example**: For $\mathbb{R}^2$
- $\{(1,0), (0,1)\}$ spans $\mathbb{R}^2$
- $\{(1,0), (0,1), (1,1)\}$ also spans $\mathbb{R}^2$
- $\{(1,1), (1,-1)\}$ also spans $\mathbb{R}^2$

## 16. Define the inner product between two quantum states

The **inner product** between quantum states $|\psi\rangle$ and $|\phi\rangle$ is:

$$\langle\psi|\phi\rangle = \text{complex number}$$

**Properties**:
1. **Conjugate symmetry**: $\langle\psi|\phi\rangle = \langle\phi|\psi\rangle^*$
2. **Linearity**: $\langle\psi|(\alpha|\phi_1\rangle + \beta|\phi_2\rangle)\rangle = \alpha\langle\psi|\phi_1\rangle + \beta\langle\psi|\phi_2\rangle$
3. **Positive definiteness**: $\langle\psi|\psi\rangle \geq 0$, equal to 0 iff $|\psi\rangle = 0$

**Computational formula**:
$$\text{If } |\psi\rangle = \sum_i \alpha_i|i\rangle \text{ and } |\phi\rangle = \sum_i \beta_i|i\rangle$$
$$\text{Then } \langle\psi|\phi\rangle = \sum_i \alpha_i^* \beta_i$$

**Physical meaning**:
- $|\langle\psi|\phi\rangle|^2$ = probability amplitude for transition
- $\langle\psi|\psi\rangle = 1$ for normalized states
- $\langle\psi|\phi\rangle = 0$ means orthogonal states

## 17. Define orthonormality in a vector space

**Orthogonality**: Two vectors $u, v$ are orthogonal if $\langle u|v\rangle = 0$

**Normality**: A vector $v$ is normalized if $\|v\| = \sqrt{\langle v|v\rangle} = 1$

**Orthonormal set**: A set $\{|\psi_i\rangle\}$ is orthonormal if:
1. **Orthogonal**: $\langle\psi_i|\psi_j\rangle = 0$ for $i \neq j$
2. **Normalized**: $\langle\psi_i|\psi_i\rangle = 1$ for all $i$

**Kronecker delta notation**: 
$$\langle\psi_i|\psi_j\rangle = \delta_{ij} = \begin{cases} 1 & \text{if } i = j \\ 0 & \text{if } i \neq j \end{cases}$$

**Examples**:
- Computational basis $\{|0\rangle, |1\rangle\}$: $\langle 0|1\rangle = 0$, $\langle 0|0\rangle = \langle 1|1\rangle = 1$
- Bell basis states are orthonormal
- Any complete basis is orthonormal

**Importance**: Simplifies calculations and provides unique decomposition.

## 18. What is the purpose of the Gram-Schmidt process?

**Purpose**: Convert linearly independent set into orthonormal set while preserving span.

**Applications**:
1. **Create orthonormal basis** from any basis
2. **Simplify calculations** using orthogonality
3. **QR decomposition** in matrix factorization
4. **Quantum state preparation**

**Algorithm steps**:
1. **Normalize first vector**
2. **Project out components** along previous vectors
3. **Normalize result**
4. **Repeat** for all vectors

**Benefits**:
- Preserves linear independence
- Maintains span of original set
- Results in orthonormal set
- Computationally systematic

## 19. Apply Gram-Schmidt to the vectors (1, 1) and (1, 0)

**Given vectors**: $\mathbf{v}_1 = (1, 1)$, $\mathbf{v}_2 = (1, 0)$

**Step 1**: Normalize $\mathbf{v}_1$
$$\mathbf{u}_1 = \frac{\mathbf{v}_1}{\|\mathbf{v}_1\|} = \frac{(1, 1)}{\sqrt{1^2 + 1^2}} = \frac{(1, 1)}{\sqrt{2}} = \left(\frac{1}{\sqrt{2}}, \frac{1}{\sqrt{2}}\right)$$

**Step 2**: Remove projection of $\mathbf{v}_2$ onto $\mathbf{u}_1$
$$\text{proj} = \langle \mathbf{v}_2, \mathbf{u}_1\rangle\mathbf{u}_1 = \left\langle (1,0), \left(\frac{1}{\sqrt{2}}, \frac{1}{\sqrt{2}}\right)\right\rangle\left(\frac{1}{\sqrt{2}}, \frac{1}{\sqrt{2}}\right)$$

$$\langle \mathbf{v}_2, \mathbf{u}_1\rangle = 1 \cdot \frac{1}{\sqrt{2}} + 0 \cdot \frac{1}{\sqrt{2}} = \frac{1}{\sqrt{2}}$$

$$\text{proj} = \frac{1}{\sqrt{2}}\left(\frac{1}{\sqrt{2}}, \frac{1}{\sqrt{2}}\right) = \left(\frac{1}{2}, \frac{1}{2}\right)$$

$$\mathbf{w}_2 = \mathbf{v}_2 - \text{proj} = (1, 0) - \left(\frac{1}{2}, \frac{1}{2}\right) = \left(\frac{1}{2}, -\frac{1}{2}\right)$$

**Step 3**: Normalize $\mathbf{w}_2$
$$\mathbf{u}_2 = \frac{\mathbf{w}_2}{\|\mathbf{w}_2\|} = \frac{\left(\frac{1}{2}, -\frac{1}{2}\right)}{\sqrt{\frac{1}{4} + \frac{1}{4}}} = \frac{\left(\frac{1}{2}, -\frac{1}{2}\right)}{\frac{1}{\sqrt{2}}} = \left(\frac{1}{\sqrt{2}}, -\frac{1}{\sqrt{2}}\right)$$

**Result**: Orthonormal set $\left\{\left(\frac{1}{\sqrt{2}}, \frac{1}{\sqrt{2}}\right), \left(\frac{1}{\sqrt{2}}, -\frac{1}{\sqrt{2}}\right)\right\}$

**Verification**: 
$$\langle \mathbf{u}_1, \mathbf{u}_2\rangle = \frac{1}{\sqrt{2}} \cdot \frac{1}{\sqrt{2}} + \frac{1}{\sqrt{2}} \cdot \left(-\frac{1}{\sqrt{2}}\right) = \frac{1}{2} - \frac{1}{2} = 0 \checkmark$$
$$\|\mathbf{u}_1\| = \|\mathbf{u}_2\| = 1 \checkmark$$

## 20. What is the difference between orthogonalization and normalization?

| Aspect | Orthogonalization | Normalization |
|--------|------------------|---------------|
| **Purpose** | Make vectors perpendicular | Make vector length = 1 |
| **Operation** | Remove parallel components | Scale by inverse of norm |
| **Formula** | $\mathbf{v}' = \mathbf{v} - \text{proj}(\mathbf{v} \text{ onto others})$ | $\mathbf{u} = \frac{\mathbf{v}}{\|\mathbf{v}\|}$ |
| **Result** | $\langle \mathbf{v}_i, \mathbf{v}_j\rangle = 0$ for $i \neq j$ | $\|\mathbf{v}\| = 1$ |
| **Preserves** | Linear independence | Direction |
| **Changes** | Direction and magnitude | Magnitude only |
| **Process** | Subtract projections | Divide by norm |

**Combined Process (Gram-Schmidt)**:
1. First orthogonalize (make perpendicular)
2. Then normalize (make unit length)
3. Result: orthonormal set

**Example**:
- **Orthogonalization**: $(1,1), (1,0) \to (1,1), \left(\frac{1}{2},-\frac{1}{2}\right)$
- **Normalization**: $(1,1) \to \left(\frac{1}{\sqrt{2}}, \frac{1}{\sqrt{2}}\right)$

## 21. What is the ket notation |ψ⟩ and bra notation ⟨ψ|?

**Dirac Notation** (Bra-ket notation):

**Ket $|\psi\rangle$**:
- Represents quantum state vector
- Column vector in matrix representation
- Element of Hilbert space
- Example: $|\psi\rangle = \alpha|0\rangle + \beta|1\rangle$

**Bra $\langle\psi|$**:
- Complex conjugate transpose of ket
- Row vector in matrix representation
- Dual vector in dual space
- $\langle\psi| = (|\psi\rangle)^\dagger$

**Bracket $\langle\phi|\psi\rangle$**:
- Inner product between states
- Bra followed by ket
- Complex number result
- Probability amplitude

**Matrix representations**:
$$|0\rangle = \begin{pmatrix} 1 \\ 0 \end{pmatrix}, \quad \langle 0| = \begin{pmatrix} 1 & 0 \end{pmatrix}$$

$$|1\rangle = \begin{pmatrix} 0 \\ 1 \end{pmatrix}, \quad \langle 1| = \begin{pmatrix} 0 & 1 \end{pmatrix}$$

$$|\psi\rangle = \begin{pmatrix} \alpha \\ \beta \end{pmatrix}, \quad \langle\psi| = \begin{pmatrix} \alpha^* & \beta^* \end{pmatrix}$$

**Advantages**:
- Compact notation
- Separates vectors from operations
- Natural for quantum mechanics
- Widely used in quantum computing literature
