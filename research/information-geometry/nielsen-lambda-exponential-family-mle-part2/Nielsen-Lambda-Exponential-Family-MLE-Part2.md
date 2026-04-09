Theorem 2. In the setting above, suppose that for any (or equivalently, for some) $p \in M$ , the pair $(\mathfrak{g}, \mathfrak{k}^p) := (\operatorname{Lie}(G), \operatorname{Lie}(K^p))$ is a symmetric pair, that is, there exists an involutive automorphism $\theta^p$ on $\mathfrak{g}$ such that $\mathfrak{k}^p = \{X \in \mathfrak{g} \mid \theta^p(X) = X\}$ . Then for any $G$ -invariant statistical structure $(g, C)$ on $M$ , $\nabla^g C \equiv 0$ holds, in particular, $(g, C)$ is conjugate symmetric.

Proof. Theorem 2 follows directly from a combination of arguments presented in [7, Chapters X and XI]. For the reader's convenience, we provide a brief outline of the proof below.

Let us define, for each $X \in \mathfrak{g}$ , a vector field $X^M \in \mathfrak{X}(M)$ by setting

$$
\left(X ^ {M}\right) _ {q} := \frac {d}{d t} \Big | _ {t = 0} \left(\exp (- t X). q\right) \in T _ {q} M
$$

for each $q \in M$ . It is well-known that the map $X \mapsto X^M$ defines a Lie algebra homomorphism from $\mathfrak{g}$ into the Lie algebra $\mathfrak{X}(M)$ of smooth vector fields on $M$ .

For each $p \in M$ , the canonical decomposition of $\mathfrak{g}$ with respect to $\mathfrak{k}^p \coloneqq \operatorname{Lie}(K^p)$ is denoted by $\mathfrak{g} = \mathfrak{k}^p + \mathfrak{p}^p$ , i.e., we put $\mathfrak{p}^p \coloneqq \{X \in \mathfrak{g} \mid \theta^p(X) = -X\}$ . Then $[\mathfrak{p}^p, \mathfrak{p}^p] \subset \mathfrak{k}^p$ , $\mathfrak{p}^p$ is an $\operatorname{Ad}(K^p)$ -stable complement of $\mathfrak{k}^p$ in $\mathfrak{g}$ , and the map

$$
\mathfrak {p} ^ {p} \to T _ {p} M, X \mapsto (X ^ {M}) _ {p} = \left. \frac {d}{d t} \right| _ {t = 0} (\exp (- t X). p)
$$

defines a linear isomorphism. For each tangent vector $v \in T_pM$ , we write $X^v$ for the unique element in $\mathfrak{p}^p$ satisfying $\left(\left(X^v\right)^M\right)_p = v$ . The affine connection $\nabla^{\mathrm{cn}}$ on $M$ , which is called the canonical connection (cf. [7, Chapter X]), is defined by putting

$$
\nabla_ {v} ^ {\mathrm {c n}} C = \left(\mathcal {L} _ {(X ^ {v}) ^ {M}} C\right) _ {p}
$$

for each $p \in M$ , each $v \in T_pM$ and each tensor field $C$ on $M$ , where $\mathcal{L}_{(X^v)^M}$ denotes the Lie derivative by the vector field $(X^v)^M$ . By the definitions of $\nabla^{\mathrm{cn}}$ and $(X^v)^M$ , one sees that $\nabla^{\mathrm{cn}}C \equiv 0$ for any $G$ -invariant tensor field $C$ on $M$ . Furthermore, $\nabla^{\mathrm{cn}}$ is torsion-free. In fact, for each $p \in M$ and each $v, w \in T_pM$ , we have $[(X^v)^M, (X^w)^M]_p = ([X^v, X^w]^M)_p = 0$ (since $[X^v, X^w] \in \mathfrak{k}^p$ and $(X^M)_p = 0$ if $X \in \mathfrak{k}^p$ ), and $\nabla_v^{\mathrm{cn}}(X^w)^M = [(X^v)^M, (X^w)^M]_p = 0$ . Hence

$$
\begin{array}{l} (T ^ {\nabla^ {\mathrm {c n}}}) _ {p} (v, w) = \nabla_ {v} ^ {\mathrm {c n}} ((X ^ {w}) ^ {M}) - \nabla_ {w} ^ {\mathrm {c n}} ((X ^ {v}) ^ {M}) - [ (X ^ {v}) ^ {M}, (X ^ {w}) ^ {M} ] _ {p} \\ = 0, \\ \end{array}
$$

where $T^{\nabla^{\mathrm{cn}}}$ denotes the torsion tensor of the affine connection $\nabla^{\mathrm{cn}}$ .

Let us fix a $G$ -invariant statistical structure $(g, C)$ on $M$ . Then by the invariance of the metric tensor field $g$ , we have $\nabla^{\mathrm{cn}} g \equiv 0$ . Further, $\nabla^g = \nabla^{\mathrm{cn}}$ holds since $\nabla^{\mathrm{cn}}$ is torsion-free. By the invariance of the $(0,3)$ -tensor field $C$ ,

$$
\nabla^ {g} C \equiv \nabla^ {\mathrm {c n}} C \equiv 0.
$$

This completes the proof.

□

# 3 Proof of Theorem 1

Let us identify $\mathcal{N}_0$ with the manifold $\mathrm{Sym}^+(n,\mathbb{R})$ by the correspondence $N(x\mid 0,\Sigma)\mapsto \Sigma$ . The identity matrix of size $n$ will be denoted by $I_{n}\in \mathrm{Sym}^{+}(n,\mathbb{R})$ . Then $I_{n}$ corresponds to the standard normal distribution $N(x\mid 0,I_n)$ on $\mathbb{R}^n$ . Since $\mathcal{N}_0 = \mathrm{Sym}^+(n,\mathbb{R})$ is an open submanifold of the vector space $\mathrm{Sym}(n,\mathbb{R})$ , we have the linear isomorphism

$$
\eta : \operatorname {S y m} (n, \mathbb {R}) \to T _ {I _ {n}} \mathcal {N} _ {0}, A \mapsto A _ {\eta} := \left. \frac {d}{d t} \right| _ {t = 0} (I _ {n} + t A).
$$

The following proposition is well-known:

Proposition 1. (see [10,11]). Under the identification $\eta$ above, the Fisher metric $g_{I_n}^F$ and the Amari-Chentsov $\alpha$ -tensor $C_{I_n}^{A(\alpha)}$ on $T_{I_n}\mathcal{N}_0 \cong \operatorname{Sym}(n,\mathbb{R})$ can be written as below:

$$
\begin{array}{l} g _ {I _ {n}} ^ {F}: \operatorname {S y m} (n, \mathbb {R}) \times \operatorname {S y m} (n, \mathbb {R}) \rightarrow \mathbb {R}, (X, Y) \mapsto \frac {1}{2} \operatorname {t r} (X Y), (1) \\ C _ {I _ {n}} ^ {A (\alpha)}: \operatorname {S y m} (n, \mathbb {R}) \times \operatorname {S y m} (n, \mathbb {R}) \times \operatorname {S y m} (n, \mathbb {R}) \rightarrow \mathbb {R}, (X, Y, Z) \mapsto \alpha \cdot \operatorname {t r} (X Y Z). (2) \\ \end{array}
$$

Let us give a proof of Theorem 1 as below:

Proof of Theorem 1. We put $G = GL(n,\mathbb{R})$ . Recall that $\mathcal{N}_0 = \operatorname{Sym}^+(n,\mathbb{R})$ is a homogeneous $G$ -space equipped with the action defined by

$$
h. \Sigma := h \Sigma h ^ {\top} \quad (\text {f o r} h \in G = G L (n, \mathbb {R}), \Sigma \in \operatorname {S y m} ^ {+} (n, \mathbb {R})).
$$

The isotropy subgroup $K = K^{I_n}$ of $G$ at the point $I_{n} \in \operatorname{Sym}^{+}(n, \mathbb{R})$ is the orthogonal group $O(n)$ . It is well-known that $(G, K) = (GL(n, \mathbb{R}), O(n))$ is a symmetric pair of Lie groups, and hence $(\mathfrak{g}, \mathfrak{k}) := (\operatorname{Lie}(G), \operatorname{Lie}(K))$ is also a symmetric pair. Thus the claim (1) in Theorem 1 is followed immediately by Theorem 2.

Let us give a proof of the claim (2) in Theorem 1. The natural $K$ -action on the tangent space $T_{I_n}\mathcal{N}_0$ is called the isotropy representation at the point $I_n$ . We write $S^3 (T_{I_n}^*\mathcal{N}_0)^K$ for the space of $K$ -invariant symmetric 3-tensors on the cotangent space at $I_n$ , i.e., on $T_{I_n}^*\mathcal{N}_0$ . Then by the general theory of invariant sections of equivariant vector bundles over homogeneous spaces, one sees that the map

$$
S ^ {3} \left(T ^ {*} \mathcal {N} _ {0}\right) ^ {G} \rightarrow S ^ {3} \left(T _ {I _ {n}} ^ {*} \mathcal {N} _ {0}\right) ^ {K}, C \mapsto C _ {I _ {n}} \tag {3}
$$

gives a linear isomorphism.

We shall define the $K = O(n)$ -representation on the vector space $\operatorname{Sym}(n, \mathbb{R})$ by putting

$$
k. X := k X k ^ {- 1} \quad (\text {f o r} X \in \operatorname {S y m} (n, \mathbb {R}), k \in O (n)).
$$

The vector space of all $K$ -invariant symmetric 3-tensors on the space $\operatorname{Sym}(n,\mathbb{R})^*$ is denoted by $S^3(\operatorname{Sym}(n,\mathbb{R})^*)^K$ . One can easily see that the identification

$\eta : \operatorname{Sym}(n, \mathbb{R}) \to T_{I_n} \mathcal{N}_0$ is an isomorphism between $K = O(n)$ -representations, where $T_{I_n} \mathcal{N}_0$ is considered as the isotropy representation of $K$ . Therefore, $S^3(T_{I_n}^* M)^K$ can be identified with $S^3(\operatorname{Sym}(n, \mathbb{R}^*)^K)$ . By combining this, the isomorphism (3) above, and Proposition 1 (2), we have a linear isomorphism from $S^3(T^* M)^G$ onto $S^3(\operatorname{Sym}(n, \mathbb{R}^*)^K)$ such that $C^{A(\alpha)}$ maps to the tensor $C^\alpha$ defined by

$$
C ^ {\alpha} (X, Y, Z) := \alpha \cdot \operatorname {t r} (X Y Z) \quad (X, Y, Z \in \operatorname {S y m} (n, \mathbb {R})).
$$

To complete the proof of the claim (2), we only need to find a linear isomorphism from $S^3 (\operatorname {Sym}(n,\mathbb{R})^*)^K$ onto $\mathcal{SP}_n^3$ such that $C^\alpha$ maps to the polynomial $\alpha \cdot (\sum_{i}x_{i}^{3})$ . For each $C\in S^3 (\operatorname {Sym}(n,\mathbb{R})^*)^K$ , we define the polynomial function $q_{C}$ on the vector space $\operatorname {Sym}(n,\mathbb{R})$ by

$$
q _ {C}: \operatorname {S y m} (n, \mathbb {R}) \to \mathbb {R}, X \mapsto C (X, X, X).
$$

The correspondence $C \mapsto q_C$ gives a linear isomorphism between $S^3(\operatorname{Sym}(n, \mathbb{R})^*)^K$ and the vector space $\mathcal{P}^3(\operatorname{Sym}(n, \mathbb{R}))^K$ of $K$ -invariant homogeneous cubic polynomial functions on $\operatorname{Sym}(n, \mathbb{R})$ . Note that $C^\alpha$ maps to the function

$$
q _ {\alpha}: \operatorname {S y m} (n, \mathbb {R}) \rightarrow \mathbb {R}, X \mapsto \alpha \cdot \operatorname {t r} \left(X ^ {3}\right).
$$

Furthermore, we shall write $D$ for the linear subspace of $\operatorname{Sym}(n,\mathbb{R})$ consisting of all diagonal matrices. Then the symmetric group $\mathfrak{S}_n$ of order $n$ acts on $D$ by permutations of subscripts. Let us denote by $\mathcal{P}^3 (D)^{\mathfrak{S}_n}$ the space of all $\mathfrak{S}_n$ -invariant homogeneous cubic polynomial functions on the vector space $D$ . We shall consider the linear isomorphism

$$
\mathcal {S P} _ {n} ^ {3} \to \mathcal {P} ^ {3} (D) ^ {\mathfrak {S} _ {n}}, P (x _ {1}, \dots , x _ {n}) \mapsto f _ {P},
$$

where the function $f_{P}$ is defined by

$$
f _ {P}: D \to \mathbb {R}, \operatorname {d i a g} (\lambda_ {1}, \dots , \lambda_ {n}) \mapsto P (\lambda_ {1}, \dots , \lambda_ {n}).
$$

Then $\mathcal{SP}_n^3$ can be identified with the space $\mathcal{P}^3 (D)^{\mathfrak{S}_n}$ . Note that the polynomial $\alpha \cdot (\sum_{i}x_{i}^{3})$ corresponds to the function

$$
f _ {\alpha}: D \to \mathbb {R}, \operatorname {d i a g} (\lambda_ {1}, \dots , \lambda_ {n}) \mapsto \alpha \cdot \sum_ {i} \lambda_ {i} ^ {3}.
$$

Thus our goal is to find a linear isomorphism $\varphi$ from $\mathcal{P}^3 (\mathrm{Sym}(n,\mathbb{R}))^K$ onto $\mathcal{P}^3 (D)^{\mathfrak{S}_n}$ such that $\varphi (q_{\alpha}) = f_{\alpha}$ . For each function $q\in \mathcal{P}^3 (\mathrm{Sym}(n,\mathbb{R}))^K$ , define $\varphi (q)\coloneqq q|_D$ by the restriction of $q$ on the linear subspace $D$ . One sees that the correspondence $q\mapsto \varphi (q)$ defines a linear map $\varphi$ from $\mathcal{P}^3 (\mathrm{Sym}(n,\mathbb{R}))^K$ to $\mathcal{P}^3 (D)^{\mathfrak{S}_n}$ , and $\varphi (q_{\alpha}) = f_{\alpha}$ . Furthermore, the map $\varphi$ is injective since for any $X\in \operatorname {Sym}(n,\mathbb{R})$ , there exists $k\in K$ such that $\mathrm{Ad}(k)X\in D$ (i.e., any symmetric matrix is diagonalizable by an orthogonal matrix). Therefore, it is enough to

show that the map $\varphi$ is surjective. Let us define the symmetric polynomial function $p_k$ on $D$ ( $k \in \mathbb{Z}_{\geq 0}$ ) by

$$
p _ {k} (\operatorname {d i a g} \left(\lambda_ {1}, \dots , \lambda_ {n}\right)) := \sum_ {i} \lambda_ {i} ^ {k} \quad (\text {f o r} \operatorname {d i a g} \left(\lambda_ {1}, \dots , \lambda_ {n}\right) \in D).
$$

Then by the theory of symmetric polynomials, one can check that $\mathcal{P}^3 (D)^{\mathfrak{S}_n}$ is spanned by the three homogeneous cubic polynomial functions $p_3,p_2p_1$ and $p_1^3$ . On the other hand, let us define the $K$ -invariant homogeneous cubic polynomial functions $q_{1},q_{2},q_{3}$ on $\operatorname {Sym}(n,\mathbb{R})$ by

$$
q _ {1} (X) := \operatorname {t r} \left(X ^ {3}\right), q _ {2} (X) := \operatorname {t r} \left(X ^ {2}\right) \cdot \operatorname {t r} (X), q _ {3} (X) := (\operatorname {t r} (X)) ^ {3}.
$$

Then $\varphi(q_1) = p_3$ , $\varphi(q_2) = p_2p_1$ and $\varphi(q_3) = p_1^3$ . This completes the proof of the claim (2).

The claim (3) follows from the claims (1), (2) and the well-known fact that the vector space $\mathcal{SP}_n^3$ is 3-dimensional if $n \geq 3$ , 2-dimensional if $n = 2$ , and 1-dimensional if $n = 1$ .

Remark 1. The following three elements form a generating set of the vector space $S^3 (\operatorname {Sym}(n,\mathbb{R})^*)^K\cong S^3 (T^*\mathcal{N}_0)_{g^F -\mathrm{CS}}^G$ :

- $C_1(X,Y,Z) \coloneqq \operatorname{tr}(XYZ)$ ,   
- $C_2(X, Y, Z) \coloneqq (1/3)(\operatorname{tr}(X)\operatorname{tr}(YZ) + \operatorname{tr}(Y)\operatorname{tr}(XZ) + \operatorname{tr}(Z)\operatorname{tr}(XY))$ ,   
- $C_3(X, Y, Z) \coloneqq \operatorname{tr}(X) \operatorname{tr}(Y) \operatorname{tr}(Z)$ .

In particular, if $n \geq 3$ , the subset $\{C_1, C_2, C_3\}$ is a basis of the vector space $S^3(\operatorname{Sym}(n, \mathbb{R})^*)^K$ . The symmetric tensor $C_1$ corresponds to the Amari-Chentsov +1-tensor field on $\mathcal{N}_0$ .

Remark 2. It is worth emphasizing that the linear isomorphism $\eta : \operatorname{Sym}(n, \mathbb{R}) \to T_{I_n} \mathcal{N}_0$ differs from the following "natural" linear isomorphism:

$$
\phi : \operatorname {S y m} (n, \mathbb {R}) \to T _ {I _ {n}} \mathcal {N} _ {0}, \quad A \mapsto \left. \frac {d}{d t} \right| _ {t = 0} (\operatorname {E x p} (- t A). I _ {n}).
$$

Indeed, it can be directly verified that $\phi = -2\eta$

Acknowledgments. The authors would like to give heartfelt thanks to Hideyuki Ishi whose suggestions were of inestimable value for this paper. The authors would also like to thank to Hitoshi Furuhata, Kento Ogawa, Yu Ohno, Hiroshi Tamaru and Koichi Tojo whose comments made enormous contribution to this paper. The first author is supported by JST SPRING, Grant Number JPMJSP2132. The second author is supported by JSPS Grants-in-Aid for Scientific Research JP20K03589, JP20K14310, JP22H01124, and JP24K06714.

Disclosure of Interests. On behalf of all authors, Hikozo Kobayashi, the corresponding author, states that there is no potential conflict of interest to declare.

# References

1. Amari, S.: Differential-Geometrical Methods in Statistics. Lecture Notes in Statistics, vol. 28. Springer-Verlag, New York (1985). https://doi.org/10.1007/978-1-4612-5056-2   
2. Ay, N., Jost, J., Lé, H.V., Schwachhöfer, L.: Information Geometry. EMG-FASMSM, vol. 64. Springer, Cham (2017). https://doi.org/10.1007/978-3-319-56478-4   
3. Furuhata, H., Inoguchi, J.-I., Kobayashi, S.-P.: A characterization of the alpha-connections on the statistical manifold of normal distributions. Information Geometry 4(1), 177–188 (2020). https://doi.org/10.1007/s41884-020-00037-z   
4. Inoguchi, J.-I., Ohno, Y.: Homogeneous statistical manifolds. arXiv preprint arXiv:2408.01647 (2024)   
5. Kobayashi, H., Ohno, Y., Okuda, T., Tamaru, H.: The moduli spaces of left-invariant statistical structures on Lie groups. in preparation   
6. Kobayashi, S.-P., Ohno, Y.: A characterization of the alpha-connections on the statistical manifold of multivariate normal distributions. Osaka J. Math. 62(2), 329-349 (2025). https://doi.org/10.18910/101132   
7. Kobayashi, S., Nomizu, K.: Foundations of Differential Geometry. Vol. II, Interscience Tracts in Pure and Applied Mathematics, vol. No. 15. Interscience Publishers John Wiley & Sons, Inc., New York-London-Sydney (1969)   
8. Lauritzen, S.L.: Statistical Manifolds. Differential geometry in statistical inference 10, 163-216 (1987). https://doi.org/10.1214/lnms/1215467061   
9. Matsuzoe, H., Takeuchi, J., Amari, S.: Equiaffine structures on statistical manifolds and Bayesian statistics. Differential Geom. Appl. 24(6), 567-578 (2006). https://doi.org/10.1016/j.difgeo.2006.02.003   
10. Mitchell, A.F.S.: The information matrix, skewness tensor and $\alpha$ -connections for the general multivariate elliptic distribution. Ann. Inst. Statist. Math. 41(2), 289-304 (1989). https://doi.org/10.1007/BF00049397   
11. Skovgaard, L.T.: A Riemannian geometry of the multivariate normal model. Scand. J. Statist. 11(4), 211-223 (1984)

# Bi-forms Approach to Potential Functions in Information Geometry

Florio M. Ciaglia $^{1}$ , Giuseppe Marmo $^{2,3}$ , Marco Pacelli $^{3,4(\boxtimes)}$ , Luca Schiavone $^{3,5}$ , and Alessandro Zampini $^{3,4,5}$

$^{1}$ Department of Mathematics, University Carlos III de Madrid, Leganés, Madrid, Spain

fciaglia@math.uc3m.es

$^{2}$ Dipartimento di Fisica "E. Pancini", Università di Napoli Federico II, Naples, Italy

<sup>3</sup> INFN-Sezione di Napoli, Naples, Italy giuseppe.marmo@na.infn.it

<sup>4</sup> Scuola Superiore Meridionale, Naples, Italy  
marco.pacelli-ssm

$^{5}$ Dipartimento di Matematica e Applicazioni "Renato Caccioppoli", Università di Napoli Federico II, Naples, Italy

{luca.schiavone, alessandro.zampini}@unina.it

Abstract. Contrast functions play a fundamental role in information geometry, providing a means for generating the geometric structures of a statistical manifold: a pseudo-Riemannian metric and a pair of torsion-free conjugate affine connections. Conventional contrast-based approaches become indeed insufficient within settings where torsion is naturally present, such as quantum information geometry. This paper introduces contrast bi-forms, a generalisation of contrast functions that systematically encode metric and connection data, allowing for arbitrary affine connections regardless of torsion. It will be shown that they provide a unified framework for statistical potentials, offering new insights into the inverse problem in information geometry. As an example, we consider teleparallel manifolds, where torsion is intrinsic to the geometry, and show how bi-forms naturally accommodate these structures.

Keywords: Contrast Function $\cdot$ Torsion $\cdot$ Bi-form $\cdot$ Teleparallel Manifold

# 1 Introduction

Contrast (or divergence) functions on a smooth manifold play a fundamental role in both mathematical theory and applications, providing a measure of distinguishability between probability distributions [4]. A crucial feature of contrast functions is that they naturally induce a pseudo-Riemannian metric $g$ and a pair of $g$ -conjugate and torsion-free affine connections $(\nabla, \nabla^{\dagger})$ on the underlying manifold $M$ [4]. The resulting structure defines a statistical manifold in

the sense of Lauritzen, capturing the essential mathematical features of parametric statistical models [11]. Within such paradigmatic examples, the metric $g$ coincides with the Fisher-Rao metric, while the torsion-free affine connections $\nabla$ and $\nabla^{\dagger}$ correspond to the $(\pm 1)$ -connections. While this framework is well suited to many applications, there are cases where the torsion-free condition does not naturally hold. A key example arises from quantum finite level systems, where the geometry of the space of faithful quantum states suggests that torsion is an inherent feature rather than an anomaly [2,9]. This motivates the introduction of a broader class of statistical structures. A statistical manifold admitting torsion (or, simply, SMAT) is a triple $(M,g,\nabla)$ , where $\nabla$ is required to be torsion-free, whereas $\nabla^{\dagger}$ may exhibit torsion. Such structures have been explored in connection with estimation theory [8] and in attempts to formulate a geometric framework for quantum information theory [10]. Extending the idea of SMATs, in this paper we introduce what we call Lauritzen manifolds, that is, triples $(M,g,\nabla)$ in which both $\nabla$ and $\nabla^{\dagger}$ may possess torsion. A natural question then arises: can these structures still be derived from a potential? As anticipated above, contrast functions are not suitable candidates, since Schwarz's theorem forces any connection derived from a contrast function to be torsion-free. This limitation has been the starting point to explore alternative formulations for potentials. We limit ourselves here to recall that Henmi and Matsuzoe [7] introduced pre-contrast functions to generate SMATs, while Zhang and Khan [16] proposed super-contrast functions as potentials for Lauritzen manifolds, both extending the standard theory of contrast functions in order to accommodate torsion. In this paper, we propose an alternative method for generating Lauritzen manifolds. Instead of relying on super-contrast functions, we adopt the formalism of bi-forms [5,6,13,15] and introduce the notion of a contrast bi-form as a suitable potential. This approach, in our opinion, offers two key advantages. First, it provides a unified framework for describing potentials, since contrast, pre-contrast, and super-contrast functions come as specific instances of bi-forms. Second, it offers a natural framework to address what we call the inverse problem in information geometry: given a statistical or Lauritzen manifold, determining whether a potential can generate it. While this problem is well understood in the case of statistical manifolds [1,12], it remains largely unexplored for SMATs and Lauritzen manifolds. Upon using the general framework of bi-forms, and developing from [7,16], we aim to establish a solid foundation for a systematic theory of potentials in information geometry. This provides a unified approach for both classical and quantum settings. Due to the space limitations of the present issue, we will describe the details and present full proofs of the statements and results discussed here in a forthcoming publication.

# 2 Contrast Bi-forms

The theory of contrast functions is based on the geometry of the Cartesian square of a manifold. Given a manifold $M$ , its Cartesian square is the product manifold $M \times M$ equipped with the canonical projections $\pi_L \colon M \times M \to M$ and

$\pi_R\colon M\times M\to M$ , which extract the left and right components, respectively:

$$
\pi_ {L} (m, n) = m \quad \text {a n d} \quad \pi_ {R} (m, n) = n. \tag {1}
$$

This geometric framework was first used by Eguchi [4] to geometrically describe an algorithm that associates a pseudo-Riemannian metric $g$ and a pair of $g$ -conjugate, torsion-free affine connections to a suitable class of 2-point functions on $M$ , i.e., smooth real-valued functions defined on the product manifold $M \times M$ known as contrast function. In the terminology commonly used in information geometry, these functions are also referred to as divergence functions or potential functions. While these terms may have slightly different technical meanings depending on the context or the class of functions considered, they all share the property of inducing the geometric structures $(g, \nabla)$ on $M$ .

In this section, we introduce a more general formulation of these geometric objects using the formalism of bi-forms.

# 2.1 Bi-Forms

A bi-form on a manifold $M$ is a section of a tensor bundle over its Cartesian square $M \times M$ . More precisely, given $(p,q) \in \mathbb{N}_0 \times \mathbb{N}_0$ , a $(p,q)$ -bi-form on $M$ is a smooth section of the vector bundle:

$$
\bigwedge^ {p} \pi_ {L} ^ {*} T ^ {\vee} M \otimes_ {M \times M} \bigwedge^ {q} \pi_ {R} ^ {*} T ^ {\vee} M, \tag {2}
$$

where $\tau_{M}^{\vee}\colon T^{\vee}M\to M$ is the cotangent bundle projection of $M$ . The space of $(p,q)$ -bi-forms is denoted by $\Omega^{p,q}(M\mid M)$ .

A $(p,q)$ -bi-form $\varpi$ can be interpreted as a $(p + q)$ -multilinear real-valued fiber-wise function on $(TM)^{p + q}$ that is skew-symmetric in the first $p$ and in the last $q$ entries. This leads to a pairing between bi-forms on $M$ and vector fields on $M$ . Given a $(p,q)$ -bi-form $\varpi$ and vector fields $\{X_i\}_{i = 1}^p$ and $\{Y_j\}_{j = 1}^q$ on $M$ , we define:

$$
\begin{array}{l} \varpi (X _ {1}, \dots , X _ {p} \mid Y _ {1}, \dots , Y _ {q}) (m, n) \\ = \varpi \left(X _ {1} (m), \dots , X _ {p} (m) \mid Y _ {1} (n), \dots , Y _ {q} (n)\right). \tag {3} \\ \end{array}
$$

Furthermore, this pairing provides a systematic method for generating blockwise alternating covariant tensors on $M$ , i.e., sections of the tensor bundle over $M$ whose total manifold is:

$$
\bigwedge^ {p} T ^ {\vee} M \otimes_ {M} \bigwedge^ {q} T ^ {\vee} M. \tag {4}
$$

Both pseudo-Riemannian metrics and the torsion tensors of affine connections - when interpreted as 3-covariant tensors via the musical isomorphism - are of this type. These can be systematically obtained from bi-forms via the diagonal embedding $\iota \colon M \to M \times M$ , defined by:

$$
\iota (m) = (m, m). \tag {5}
$$

Indeed, this map induces the operator:

$$
\iota^ {*} \colon \Omega^ {p, q} (M \mid M) \rightarrow \Omega^ {p} (M) \otimes_ {C ^ {\infty} (M)} \Omega^ {q} (M), \tag {6}
$$

where the tensor product is taken over the ring of smooth functions on $M$ . This operator assigns to any $(p,q)$ -bi-form $\varpi$ on $M$ the block-wise alternating tensor:

$$
\left(\iota^ {*} \varpi\right) \left(Z _ {1}, \dots , Z _ {p + q}\right) = \iota^ {*} \left(\varpi \left(Z _ {1}, \dots , Z _ {p} \mid Z _ {p + 1}, \dots , Z _ {p + q}\right)\right), \tag {7}
$$

where $\{Z_i\}_{i=1}^{p+q}$ are vector fields on $M$ . Since the pairing is local, the operator $\iota^*$ naturally restricts to the space of $(p,q)$ -bi-forms that are defined on an open neighborhood of the diagonal submanifold $\Delta_M$ of $M \times M$ . We denote this space by $\Omega_{\Delta_M}^{p,q}(M \mid M)$ .

Another useful operator on bi-forms arises in terms of a distinguished map associated to the Cartesian square of a manifold, namely the swap map $s \colon M \times M \to M \times M$ defined by:

$$
s (m, n) = (n, m). \tag {8}
$$

This map interchanges the roles of the left and right projections, providing a systematic way to mirror properties between left and right components. Since $s$ induces a fiber bundle isomorphism between $\pi_L$ and $\pi_R$ , it induces the operator:

$$
s ^ {*} \colon \Omega^ {p, q} (M \mid M) \rightarrow \Omega^ {q, p} (M \mid M), \tag {9}
$$

which acts on a $(p,q)$ -bi-form $\varpi$ on $M$ as:

$$
\left(s ^ {*} \varpi\right) \left(X _ {1}, \dots , X _ {q} \mid Y _ {1}, \dots , Y _ {p}\right) = s ^ {*} \left(\varpi \left(Y _ {1}, \dots , Y _ {p} \mid X _ {1}, \dots , X _ {q}\right)\right), \tag {10}
$$

where $\{X_{i}\}_{i = 1}^{q}$ and $\{Y_j\}_{j = 1}^p$ are vector fields on $M$ . Since the pairing is local and $s$ fixes the diagonal submanifold $\Delta_M$ of $M\times M$ , also the operator $s^*$ restricts to $s^*:\varOmega_{\Delta_M}^{p,q}(M\mid M)\to\varOmega_{\Delta_M}^{q,p}(M\mid M)$ .

Finally, we discuss a structure on the space of bi-forms that has an interesting interpretation from the statistical point of view, that is the commutative bi-complex of bi-forms. The vertical distribution induced by $\pi_R$ defines a flat generalized Ehresmann connection on the fiber bundle $\pi_L$ , inducing a decomposition of the tangent bundle of $M\times M$ as the Whitney sum of the vertical distributions corresponding to $\pi_L$ and $\pi_R$ . This decomposition naturally gives rise to a pair of differential operators $\mathrm{d}^L$ and $\mathrm{d}^R$ acting on bi-forms, that we define as follows.

The left differential operator $\mathrm{d}^L$ increases the left degree and is given by:

$$
\mathrm {d} ^ {L}: \Omega^ {p, q} (M \mid M) \rightarrow \Omega^ {p + 1, q} (M \mid M), \tag {11}
$$

with the explicit action:

$$
\begin{array}{l} \mathrm {d} ^ {L} \varpi \left(X _ {0}, X _ {1}, \dots , X _ {p} \mid Y _ {1}, \dots , Y _ {q}\right) \\ = \sum_ {i = 0} ^ {p} (- 1) ^ {i} \mathcal {L} _ {X _ {i} ^ {L}} \left(\varpi \left(X _ {0}, \dots , \check {X} _ {i}, \dots , X _ {p} \mid Y _ {1}, \dots , Y _ {q}\right)\right) \\ + \sum_ {0 \leq a <   b \leq p} (- 1) ^ {a + b} \varpi ([ X _ {a}, X _ {b} ], X _ {0}, \dots , \check {X} _ {a}, \dots , \check {X} _ {b}, \dots , X _ {p} \mid Y _ {1}, \dots , Y _ {q}), \tag {12} \\ \end{array}
$$

where $\varpi$ is a $(p,q)$ -bi-form on $M$ , the elements $\{X_i\}_{i=0}^p$ , $\{Y_j\}_{j=1}^q$ are vector fields on $M$ , and $X^L$ denotes the $\pi_L$ -horizontal lift of the vector field $X$ . The check notation indicates omission of the corresponding vector field. It is possible to prove that $\mathrm{d}^L$ satisfies the cohomology condition $\mathrm{d}^L \circ \mathrm{d}^L = 0$ , which means that bi-forms can be studied within a differential complex.

We introduce the right differential operator $\mathrm{d}^R$ , which increases the right degree, and is given by:

$$
\mathrm {d} ^ {R} \colon \Omega^ {p, q} (M \mid M) \rightarrow \Omega^ {p, q + 1} (M \mid M). \tag {13}
$$

Instead of writing its full expression explicitly, which would be analogous to (12), we use the swap map $s^*$ to define it as:

$$
\mathrm {d} ^ {R} \varpi = s ^ {*} \left(\mathrm {d} ^ {L} \left(s ^ {*} \varpi\right)\right), \tag {14}
$$

where $\varpi$ is a $(p,q)$ -bi-form on $M$ . As for the case of the $\mathrm{d}^L$ operator, the operator $\mathrm{d}^R$ satisfies the cohomology property $\mathrm{d}^R \circ \mathrm{d}^R = 0$ . Furthermore, these two operators commute, i.e. $\mathrm{d}^L \circ \mathrm{d}^R = \mathrm{d}^R \circ \mathrm{d}^L$ . Thus, the space of bi-forms is endowed with the structure of a commutative bi-complex.

# 2.2 Contrast Bi-forms

Contrast functions, as characterized by Eguchi, are 2-point functions inducing pseudo-Riemannian metrics. Similarly, 2-covariant tensors on a manifold $M$ arise from $(2,0)$ , $(1,1)$ , $(0,2)$ -bi-forms. Since pseudo-Riemannian metrics are symmetric, the only suitable choice for encoding such a structure is a $(1,1)$ -bi-form.

A contrast bi-form is an element $\varpi \in \Omega_{\Delta_M}^{1,1}(M \mid M)$ such that $\iota^*\varpi$ defines a pseudo-Riemannian metric, denoted by $g^{\varpi} = \iota^{*}\varpi$ (cf. (7)). The associated affine connection $\nabla^{\varpi}$ is defined implicitly by:

$$
g ^ {\varpi} \left(\nabla_ {Z} ^ {\varpi} X, Y\right) = \iota^ {*} \left(\mathcal {L} _ {Z ^ {L}} \left(\varpi (X \mid Y)\right)\right), \tag {15}
$$

where $X, Y, Z$ are vector fields on $M$ and $Z^L$ denotes the $\pi_L$ -horizontal lift of $Z$ . The dual affine connection is induced by $s^*\varpi$ , and we denote it as $\varpi^\dagger = s^*\varpi$ .

Remark 1. Viewing $\varpi$ as a fiber-wise bilinear function $TM\times TM\to \mathbb{R}$ is coherent with the definitions of super-contrast functions of Zhang and Khan [16].

The commutative bi-complex structure provides a characterization of torsion properties of the induced connections.

Proposition 1. Let $\varpi$ be a contrast bi-form on a manifold $M$ . The connection $\nabla^{\varpi}$ is torsion-free if and only if $\iota^{*}\mathrm{d}^{L}\varpi = 0$ , while the dual connection $\nabla^{\varpi^{\dagger}}$ is torsion-free if and only if $\iota^{*}\mathrm{d}^{R}\varpi = 0$ .