Introduction
Many systems can be described at several levels of resolution. Individual orders contribute to market activity, interactions among individuals contribute to population behaviour, and microscopic physical interactions contribute to macroscopic observables. This work investigates the mathematical conditions under which a detailed description of a system admits a reduced description of its collective behaviour.
The recurrence of mathematical structures across different applications motivates this investigation. A shared equation form provides a basis for comparison, while establishing a common mechanism requires explicit assumptions and derivations. Our aim is to determine which properties of evolution and aggregation can be expressed within a common framework.
We begin with a finite-dimensional linear system,
[
\dot z(t)=Az(t),
]
where (z(t)\in\mathbb R^n) represents the detailed state and (A\in\mathbb R^{n\times n}) is constant. We define a reduced state
[
y(t)=Cz(t),
]
where (C\in\mathbb R^{k\times n}) is constant, has full row rank, and satisfies (1\leq k<n). The central question is whether the retained variables determine their own evolution: does a constant matrix (B\in\mathbb R^{k\times k}) exist such that
[
\dot y(t)=By(t)
]
for every microscopic initial condition (z(0)\in\mathbb R^n)?
For a proposed matrix (B), exact closure holds precisely when
[
CA=BC.
]
Such a matrix exists if and only if (\ker C) is invariant under (A). This condition ensures that differences discarded by aggregation cannot subsequently affect the retained variables.
This established result in exact linear reduction, also called lumping, provides an elementary foundation for the broader investigation [1]. Subsequent extensions must specify how interactions generate collective observables, when reduced equations remain exact, and when additional variables, memory or controlled approximations are required. The wider objective is to investigate whether market, population and physical systems admit descriptions governed by common evolution and aggregation principles. The linear results below establish conditions for exact reduction within a specified model class; the scope of any broader unification remains to be established.
Linear microscopic dynamics
Let (z:I\to\mathbb R^n) be a differentiable state trajectory on a time interval (I) containing (0). Its components are
[
z(t)=
\begin{bmatrix}
z_1(t)\
z_2(t)\
\vdots\
z_n(t)
\end{bmatrix},
\qquad
\dot z(t)=\frac{dz(t)}{dt}=
\begin{bmatrix}
\dot z_1(t)\
\dot z_2(t)\
\vdots\
\dot z_n(t)
\end{bmatrix}.
]
A constant-coefficient linear system has the form
[
\dot z(t)=Az(t),
\qquad
A=
\begin{bmatrix}
a_{11}&a_{12}&\cdots&a_{1n}\
a_{21}&a_{22}&\cdots&a_{2n}\
\vdots&\vdots&\ddots&\vdots\
a_{n1}&a_{n2}&\cdots&a_{nn}
\end{bmatrix}.
]
Equivalently, for each (i=1,\ldots,n),
[
\dot z_i(t)=\sum_{j=1}^n a_{ij}z_j(t).
]
Each row of (A) forms a weighted sum of the current state components. The entries (a_{ij}) are numerical coefficients, not differentiation operations. The derivative is taken on the left-hand side.
The system is autonomous because its right-hand side has no explicit dependence on time. It is linear because the rate is a linear function of the current state. These are distinct properties: an autonomous equation can also be nonlinear.
An arbitrary differentiable trajectory need not satisfy a constant-coefficient linear system. The equation (\dot z=Az) is an assumption about the dynamics, which must be justified for the system under consideration.
A differentiation example: sine and cosine
Consider
[
z(t)=
\begin{bmatrix}
\sin t\
\cos t
\end{bmatrix}.
]
Differentiation gives
[
\dot z(t)=
\begin{bmatrix}
\cos t\
-\sin t
\end{bmatrix}
\underbrace{
\begin{bmatrix}
0&1\
-1&0
\end{bmatrix}
}{A{\mathrm{rot}}}
\begin{bmatrix}
\sin t\
\cos t
\end{bmatrix}.
]
The chosen components are closed under differentiation: each derivative is a constant linear combination of the components already present. This establishes a linear evolution law for the two-component state. It does not yet reduce its dimension.
Reconstruction from one scalar
A representation of the form
[
z(t)=v,h(t),
\qquad
v=
\begin{bmatrix}
v_1\v_2
\end{bmatrix}
]
with constant real (v) would place every state on the fixed line spanned by (v). The sine and cosine trajectory does not lie on such a line:
[
z(0)=
\begin{bmatrix}0\1\end{bmatrix},
\qquad
z(\pi/2)=
\begin{bmatrix}1\0\end{bmatrix}.
]
These two states are linearly independent. Consequently, no constant vector (v) and scalar function (h) can give the proposed representation for all times.
Such reconstruction can work on a restricted state set. For example,
[
z(t)=
\begin{bmatrix}
e^{-t}\2e^{-t}
\end{bmatrix}
\begin{bmatrix}1\2\end{bmatrix}h(t),
\qquad h(t)=e^{-t}.
]
Here the admissible trajectory lies on a known line, so one scalar determines both components. This does not provide reconstruction for arbitrary initial states in (\mathbb R^2).
A unit-circle trajectory can also be described by an angular variable,
[
z(t)=
\begin{bmatrix}
\sin\theta(t)\
\cos\theta(t)
\end{bmatrix}.
]
That is a nonlinear reconstruction on a restricted state set, rather than multiplication by a constant vector.
Keeping sine alone
Suppose we retain only
[
y(t)=\sin t,
\qquad
C=
\begin{bmatrix}1&0\end{bmatrix}.
]
Then
[
\dot y(t)=\cos t.
]
Knowing (y) does not determine this derivative. At (t=0) and (t=\pi), the retained value is (y=0), but the derivatives are (1) and (-1), respectively. Thus no single-valued first-order autonomous equation (\dot y=G(y)) describes this scalar trajectory for all times.
The matrix criterion detects the same problem. For a scalar (B=(b)),
[
CA_{\mathrm{rot}}=
\begin{bmatrix}0&1\end{bmatrix},
\qquad
BC=
\begin{bmatrix}b&0\end{bmatrix}.
]
They cannot be equal.
Although (y) satisfies (\ddot y=-y), this second-order equation requires both (y(0)) and (\dot y(0)). Writing one second-order equation has therefore not reduced the number of state variables from two to one.
Aggregation and exact closure
An aggregation is a map from the detailed state to a chosen reduced state. In the linear setting,
[
y=Cz.
]
This is a map from (\mathbb R^n) to (\mathbb R^k). It need not permit reconstruction of the original state.
Because (C) is constant,
[
\dot y=C\dot z=CAz.
]
A proposed closed linear equation (\dot y=By) instead gives
[
\dot y=BCz.
]
These expressions agree for every microscopic state precisely when
[
\boxed{CA=BC.}
]
The two products have a direct interpretation. In (CAz), microscopic evolution is evaluated before aggregation. In (BCz), the state is aggregated before its reduced rate is evaluated.
The purpose of exact closure is to preserve the evolution of the chosen aggregate. It does not require preserving every detail of the microscopic state.
A worked example: supply and demand imbalance
For illustration, let (S(t)) and (D(t)) represent comparable supply and demand quantities, defined using the same units, price reference and horizon. Set
[
z(t)=
\begin{bmatrix}
S(t)\D(t)
\end{bmatrix}.
]
We posit the following dynamics to illustrate the mathematics:
[
\dot S=-2S+D,
\qquad
\dot D=S-2D,
]
or
[
\dot z=A_{\mathrm{sym}}z,
\qquad
A_{\mathrm{sym}}=
\begin{bmatrix}
-2&1\
1&-2
\end{bmatrix}.
]
Time units are chosen so that the coefficients have these numerical values. An empirical application would need to justify these dynamics from observations or a market mechanism.
Define the imbalance using the convention
[
y=S-D.
]
Positive (y) therefore means excess supply. The aggregation matrix is
[
C=
\begin{bmatrix}1&-1\end{bmatrix},
\qquad y=Cz.
]
Differentiating the aggregate gives
[
\begin{aligned}
\dot y
&=\dot S-\dot D\
&=(-2S+D)-(S-2D)\
&=-3S+3D\
&=-3(S-D)\
&=-3y.
\end{aligned}
]
Thus the reduced matrix is (B=(-3)).
The matrix verification is
[
CA_{\mathrm{sym}}=
\begin{bmatrix}-3&3\end{bmatrix}
(-3)\begin{bmatrix}1&-1\end{bmatrix}
=BC.
]
We have obtained an exact aggregate equation,
[
\boxed{\dot y=-3y,\qquad y(t)=y(0)e^{-3t}.}
]
What information is discarded?
The detailed states
[
z^{(1)}(0)=
\begin{bmatrix}5\3\end{bmatrix},
\qquad
z^{(2)}(0)=
\begin{bmatrix}50\48\end{bmatrix}
]
both have imbalance (y(0)=2). Their total quantities differ substantially. Nevertheless, under the specified dynamics, both have the same future imbalance,
[
y(t)=2e^{-3t}.
]
To identify the discarded information, define
[
q=S+D.
]
Then
[
\dot q=-q,
\qquad q(t)=q(0)e^{-t}.
]
Reconstruction requires both (q) and (y):
[
S=\frac{q+y}{2},
\qquad
D=\frac{q-y}{2}.
]
The imbalance alone does not recover the total quantity, but the total quantity is unnecessary for predicting imbalance within this model.
A link from imbalance to price changes would require a separately specified mechanism and empirical validation.
Generalising the example
The same calculation works for
[
\dot S=-\alpha S+\beta D,
\qquad
\dot D=\beta S-\alpha D.
]
For (y=S-D),
[
\dot y=-(\alpha+\beta)y.
]
For (q=S+D),
[
\dot q=-(\alpha-\beta)q.
]
When (\alpha>\beta\geq0), both quantities decay for positive time. The numerical example corresponds to (\alpha=2) and (\beta=1). The symmetry of the two interaction rules makes the difference and sum evolve independently.
A counterexample: imbalance need not close
Keep the same aggregation (y=S-D), but change the microscopic dynamics to
[
\dot S=-S,
\qquad
\dot D=-2D,
]
so that
[
A_{\mathrm{asym}}=
\begin{bmatrix}
-1&0\
0&-2
\end{bmatrix}.
]
Now
[
\dot y=-S+2D.
]
For the two initial states used above, the imbalance is again (2), but
[
\left.\dot y^{(1)}\right|{t=0}=-5+2(3)=1,
\qquad
\left.\dot y^{(2)}\right|{t=0}=-50+2(48)=46.
]
The same initial aggregate has different derivatives. Therefore no first-order autonomous equation depending only on (y) describes the aggregate for all microscopic initial conditions.
In terms of the total quantity,
[
\dot y=\frac{q-3y}{2}.
]
Here the discarded variable (q) affects the imbalance rate.
The matrix calculation gives
[
CA_{\mathrm{asym}}=
\begin{bmatrix}-1&2\end{bmatrix},
\qquad
BC=
\begin{bmatrix}b&-b\end{bmatrix}.
]
No scalar (b) makes these equal. Defining an aggregate is therefore a separate step from proving that its dynamics close.
The kernel condition and the general proof
The kernel of (C) is
[
\ker C={v\in\mathbb R^n:Cv=0}.
]
It consists of state differences that the aggregation cannot detect:
[
Cz=C\widetilde z
\quad\Longleftrightarrow\quad
z-\widetilde z\in\ker C.
]
For the imbalance map (C=(1\ \ -1)),
[
\ker C=
\left{
\begin{bmatrix}s\s\end{bmatrix}:s\in\mathbb R
\right}.
]
An equal change in supply and demand leaves the imbalance unchanged.
In the successful example,
[
A_{\mathrm{sym}}
\begin{bmatrix}s\s\end{bmatrix}
\begin{bmatrix}-s\-s\end{bmatrix}
\in\ker C.
]
In the counterexample,
[
CA_{\mathrm{asym}}
\begin{bmatrix}s\s\end{bmatrix}
=s,
]
which is nonzero whenever (s\neq0). Previously invisible differences can therefore affect the retained rate.
Exact linear closure criterion
Let (A\in\mathbb R^{n\times n}) and (C\in\mathbb R^{k\times n}) be constant, with (C) of full row rank. The following statements are equivalent:
There exists a constant (B\in\mathbb R^{k\times k}) such that (y=Cz) satisfies (\dot y=By) for every solution of (\dot z=Az) and every initial state.
There exists a constant (B) satisfying (CA=BC).
(A(\ker C)\subseteq\ker C).
When these statements hold, (B) is unique.
Proof. If statement 1 holds, differentiating (y=Cz) and evaluating at time (0) gives
[
CAz(0)=BCz(0).
]
Since (z(0)) is arbitrary, (CA=BC). Conversely, if (CA=BC), then every microscopic solution satisfies
[
\dot y=C\dot z=CAz=BCz=By.
]
This proves the equivalence of statements 1 and 2.
Suppose statement 2 holds and take an arbitrary (v\in\ker C). Then
[
C(Av)=CAv=BCv=B0=0.
]
Thus (Av\in\ker C), proving statement 3.
Conversely, assume statement 3. For any (y\in\mathbb R^k), choose (z) with (Cz=y), which is possible because (C) has full row rank. Define
[
By:=CAz.
]
If (Cz=C\widetilde z), then (z-\widetilde z\in\ker C). Invariance implies
[
CA(z-\widetilde z)=0,
]
so the definition is independent of the choice of microscopic representative. It defines a linear map (B) with (BCz=CAz) for every (z), hence (BC=CA).
Finally, if (B_1C=B_2C=CA), surjectivity of (C) gives (B_1y=B_2y) for every (y\in\mathbb R^k). Therefore (B_1=B_2). (\square)
Exact aggregate prediction and information loss
Under these equivalent conditions, the aggregate solution is
[
y(t)=e^{Bt}Cz(0),
]
and the microscopic and aggregate flows satisfy
[
Ce^{At}=e^{Bt}C.
]
Thus two initial states with the same aggregate have the same aggregate trajectory.
However, when (k<n), rank–nullity gives
[
\dim(\ker C)=n-k>0.
]
Consequently, (C) is not injective on (\mathbb R^n), and arbitrary microscopic states cannot be uniquely reconstructed from (y). Exact closure preserves the dynamics of the chosen observable while permitting loss of microscopic information.
These examples establish a precise starting question for further work: which observables retain enough information for their own evolution, and which additional variables or approximation terms are needed when exact closure fails?
Reference
[1] Z. Rózsa and J. Tóth, Exact linear lumping in abstract spaces, Proceedings of the 7th Colloquium on the Qualitative Theory of Differential Equations, No. 21, pp. 1–20, 2004. Theorems 1 and 4 discuss the intertwining and kernel-invariance conditions. Full text.
