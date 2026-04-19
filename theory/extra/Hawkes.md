Hawkes Processes
Patrick J. Laub · Thomas Taimre · Philip K. Pollett
Last edited: July 10, 2015
Abstract Hawkes processes are a particularly interesting class of stochastic process that have been
applied in diverse areas, from earthquake modelling to ﬁnancial analysis. They are point processes
whose deﬁning characteristic is that they ‘self-excite’, meaning that each arrival increases the rate of
future arrivals for some period of time. Hawkes processes are well established, particularly within the
ﬁnancial literature, yet many of the treatments are inaccessible to one not acquainted with the topic.
This survey provides background, introduces the ﬁeld and historical developments, and touches upon
all major aspects of Hawkes processes.
1 Introduction
Events that are observed in time frequently cluster natually. An earthquake typically increases the
geological tension in the region where it occurs, and aftershocks likely follow [1]. A ﬁght between rival
gangs can ignite a spate of criminal retaliations [2]. Selling a signiﬁcant quantity of a stock could
precipitate a trading ﬂurry or, on a larger scale, the collapse of a Wall Street investment bank could
send shockwaves through the world’s ﬁnancial centres [3].
The Hawkes process (HP) is a mathematical model for these ‘self-exciting’ processes, named after
its creator Alan G. Hawkes [4]. The HP is a counting process that models a sequence of ‘arrivals’ of
some type over time, for example, earthquakes, gang violence, trade orders, or bank defaults. Each
arrival excites the process in the sense that the chance of a subsequent arrival is increased for some
time period after the initial arrival. As such, it is a non-Markovian extension of the Poisson process.
Some datasets, such as the number of companies defaulting on loans each year [5], suggest that the
underlying process is indeed self exciting. Furthermore, using the basic Poisson process to model say
the arrival of trade orders of a stock is highly inappropriate, because participants in equity markets
exhibit a herding behaviour, a standard example of economic reﬂexivity [6].
The process of generating, model ﬁtting, and testing the goodness of ﬁt of HPs is examined in
this survey. As the HP literature in ﬁnancial ﬁelds is particularly well developed, applications in these
areas are considered chieﬂy here.
P. J. Laub
Department of Mathematics, The University of Queensland, Qld 4072, Australia, and
Department of Mathematics, Aarhus University, Ny Munkegade, DK-8000 Aarhus C, Denmark.
E-mail: p.laub@[uq.edu.au|math.au.dk]
T. Taimre
Department of Mathematics, The University of Queensland, Qld 4072, Australia
E-mail: t.taimre@uq.edu.au
P. K. Pollett
Department of Mathematics, The University of Queensland, Qld 4072, Australia
E-mail: pkp@maths.uq.edu.au
arXiv:submit/1282874  [math.PR]  10 Jul 2015

Patrick J. Laub et al.
t1
t2
t3
t4
t5t6
t7
N(t)
t
Fig. 1: An example point process realisation {t1, t2, . . . } and corresponding counting process N(t).
2 Background
Before discussing HPs, some key concepts must be elucidated. Firstly, we brieﬂy give deﬁnitions for
counting processes and point processes, thereby setting essential notation. Secondly, we discuss the
lesser-known conditional intensity function and compensator, both core concepts for a clear under-
standing of HPs.
2.1 Counting and point processes
We begin with the deﬁnition of a counting process.
Deﬁnition 1 (Counting process) A counting process is a stochastic process (N(t) : t ≥0) taking
values in N0 that satisﬁes N(0) = 0, is almost surely (a.s.) ﬁnite, and is a right-continuous step
function with increments of size +1. Further, denote by (H(u) : u ≥0) the history of the arrivals up
to time u. (Strictly speaking H(·) is a ﬁltration, that is, an increasing sequence of σ-algebras.)
A counting process can be viewed as a cumulative count of the number of ‘arrivals’ into a system
up to the current time. Another way to characterise such a process is to consider the sequence of
random arrival times T = {T1, T2, . . . } at which the counting process N(·) has jumped. The process
deﬁned as these arrival times is called a point process, described in Deﬁnition 2 (adapted from [7]);
see Fig. 1 for an example point process and its associated counting process.
Deﬁnition 2 (Point process) If a sequence of random variables T = {T1, T2, . . . }, taking values in
[0, ∞), has P(0 ≤T1 ≤T2 ≤. . . ) = 1, and the number of points in a bounded region is a.s. ﬁnite, then
T is a (simple) point process.
The counting and point process terminology is often interchangeable. For example, if one refers to
a Poisson process or a HP then the reader must infer from the context whether the counting process
N(·) or the point process of times T is being discussed.

Hawkes Processes
One way to characterise a particular point process is to specify the distribution function of the
next arrival time conditional on the past. Given the history up until the last arrival u, H(u), deﬁne
(as per [8]) the conditional c.d.f. (and p.d.f.) of the next arrival time Tk+1 as
F ∗(t | H(u)) =
Z t
u
P(Tk+1 ∈[s, s + ds] | H(u)) ds =
Z t
u
f∗(s | H(u)) ds .
The joint p.d.f. for a realisation {t1, t2, . . . , tk} is then, by the chain rule,
f(t1, t2, . . . , tk) =
k
Y
i=1
f∗(ti | H(ti−1)) .
(1)
In the literature the notation rarely speciﬁes H(·) explicitly, but rather a superscript asterisk is
used (see for example [9]). We follow this convention and abbreviate F ∗(t | H(u)) and f∗(t | H(u)) to
F ∗(t) and f∗(t), respectively.
Remark 1 The function f∗(t) can be used to classify certain classes of point processes. For example,
if a point process has an f∗(t) which is independent of H(t) then the process is a renewal process.
2.2 Conditional intensity functions
Often it is diﬃcult to work with the conditional arrival distribution f∗(t). Instead, another characteri-
sation of point processes is used: the conditional intensity function. Indeed if the conditional intensity
function exists it uniquely characterises the ﬁnite-dimensional distributions of the point process (see
Proposition 7.2.IV of [9]). Originally this function was called the hazard function [10] and was deﬁned
as
λ∗(t) =
f∗(t)
1 −F ∗(t) .
(2)
Although this deﬁnition is valid, we prefer an intuitive representation of the conditional intensity
function as the expected rate of arrivals conditioned on H(t):
Deﬁnition 3 (Conditional intensity function) Consider a counting process N(·) with associated
histories H(·). If a (non-negative) function λ∗(t) exists such that
λ∗(t) = lim
h↓0
E[N(t + h) −N(t) | H(t)]
h
which only relies on information of N(·) in the past (that is, λ∗(t) is H(t)-measurable), then it is called
the conditional intensity function of N(·).
The terms ‘self-exciting’ and ‘self-regulating’ can be made precise by using the conditional intensity
function. If an arrival causes the conditional intensity function to increase then the process is said to
be self-exciting. This behaviour causes temporal clustering of T . In this setting λ∗(t) must be chosen to
avoid explosion, where we use the standard deﬁnition of explosion as the event that N(t) −N(s) = ∞
for t −s < ∞. See Fig. 2 for an example realisation of such a λ∗(t).
Alternatively, if the conditional intensity function drops after an arrival the process is called self-
regulating and the arrival times appear quite temporally regular. Such processes are not examined
hereafter, though an illustrative example would be the arrival of speeding tickets to a driver over time
(assuming each arrival causes a period of heightened caution when driving).

Patrick J. Laub et al.
λ∗(t)
t
t1 t2
t3
t4
t5
λ
t6 t7
Fig. 2: An example conditional intensity function for a self-exciting process.
2.3 Compensators
Frequently the integrated conditional intensity function is needed (for example, in parameter estima-
tion and goodness of ﬁt testing); it is deﬁned as follows.
Deﬁnition 4 (Compensator) For a counting process N(·) the non-decreasing function
Λ(t) =
Z t
0
λ∗(s) ds
is called the compensator of the counting process.
In fact, a compensator is usually deﬁned more generally and exists even when λ∗(·) does not exist.
Technically Λ(t) is the unique H(t) predictable function, with Λ(0) = 0, and is non-decreasing, such
that N(t) = M(t) + Λ(t) almost surely for t ≥0 and where M(t) is an H(t) local martingale, whose
existence is guaranteed by the Doob–Meyer decomposition theorem. However, for HPs λ∗(·) always
exists (in fact, as we shall see in Section 3, a HP is deﬁned in terms of this function) and therefore
Deﬁnition 4 is suﬃcient for our purposes.
3 Literature review
With essential background and core concepts outlined in Section 2, we now turn to discussing HPs,
including their useful immigration–birth representation. We brieﬂy touch on generalisations, before
turning to a illustrative account of HPs for ﬁnancial applications.
3.1 The Hawkes process
Point processes gained a signiﬁcant amount of attention in the ﬁeld of statistics during the 1950s and
1960s. First, Cox [10] introduced the notion of a doubly stochastic Poisson process (now called the Cox
process) and Bartlett [11,12,13] investigated statistical methods for point processes based on their
power spectral densities. At IBM Research Laboratories, Lewis [14] formulated a point process model
(for computer failure patterns) which was a step in the direction of the HP. The activity culminated in
the signiﬁcant monograph by Cox and Lewis [15] on time series analysis; modern researchers appreciate

Hawkes Processes
this text as an important development of point process theory since it canvassed their wide range of
applications [9, p. 16].
It was in this context that Hawkes [4] set out to bring Bartlett’s spectral analysis approach to a
new type of process: a self-exciting point process. The process Hawkes described was a one-dimensional
point process (though originally speciﬁed for t ∈R as opposed to t ∈[0, ∞)), and is deﬁned as follows.
Deﬁnition 5 (Hawkes process) Consider (N(t) : t ≥0) a counting process, with associated history
(H(t) : t ≥0), that satisﬁes
P(N(t + h) −N(t) = m | H(t)) =







λ∗(t) h + o(h) ,
m = 1
o(h) ,
m > 1
1 −λ∗(t) h + o(h) ,
m = 0
.
Suppose the process’ conditional intensity function is of the form
λ∗(t) = λ +
Z t
0
µ(t −u) dN(u)
(3)
for some λ > 0 and µ : (0, ∞) →[0, ∞) which are called the background intensity and excitation function
respectively. Assume that µ(·) ̸= 0 to avoid the trivial case, that is, a homogeneous Poisson process.
Such a process N(·) is a Hawkes process.
Remark 2 The deﬁnition above has t as non-negative, however an alternative form of the HP is to
consider arrivals for t ∈R and set N(t) as the number of arrivals in (0, t]. Typically HP results hold
for both deﬁnitions, though we will specify that this second t ∈R deﬁnition is to be used when it is
required.
(a)
0
0
t
Count
N(t)
E[N(t)]
(b)
0
0
t
Intensity
λ∗(t)
E[λ∗(t)]
Fig. 3: (a) A typical Hawkes process realisation N(t), and its associated λ∗(t) in (b), both plotted
against their expected values.
Remark 3 In modern terminology, Deﬁnition 5 describes a linear HP—the nonlinear version is given
later in Deﬁnition 6. Unless otherwise qualiﬁed, the HPs in this paper will refer to this linear form.
A realisation of a HP is shown in Fig. 3 with the associated path of the conditional intensity
process. Hawkes [16] soon extended this single point process into a collection of self- and mutually-
exciting point processes, which we will turn to discussing after elaborating upon this one-dimensional
process.

Patrick J. Laub et al.
3.2 Hawkes conditional intensity function
The form of the Hawkes conditional intensity function in (3) is consistent with the literature though
it somewhat obscures the intuition behind it. Using {t1, t2, . . . , tk} to denote the observed sequence of
past arrival times of the point process up to time t, the Hawkes conditional intensity is
λ∗(t) = λ +
X
ti<t
µ(t −ti) .
The structure of this λ∗(·) is quite ﬂexible and only requires speciﬁcation of the background intensity
λ > 0 and the excitation function µ(·). A common choice for the excitation function is one of expo-
nential decay; Hawkes [4] originally used this form as it simpliﬁed his theoretical derivations [17]. In
this case µ(t) = α e−βt, which is parameterised by constants α, β > 0, and hence
λ∗(t) = λ +
Z t
−∞
αe−β(t−s) dN(s) = λ +
X
ti<t
αe−β(t−ti) .
(4)
The constants α and β have the following interpretation: each arrival in the system instantaneously
increases the arrival intensity by α, then over time this arrival’s inﬂuence decays at rate β.
Another frequent choice for µ(·) is a power law function, giving
λ∗(t) = λ +
Z t
−∞
k
(c + (t −s))p dN(s) = λ +
X
ti<t
k
(c + (t −ti))p
with some positive scalars c, k, and p. The power law form was popularised by the geological model
called Omori’s law, used to predict the rate of aftershocks caused by an earthquake [18]. More com-
putationally eﬃcient than either of these excitation functions is a piecewise linear function as in
[19]. However, the remaining discussion will focus on the exponential form of the excitation function,
sometimes referred to as the HP with exponentially decaying intensity.
One can consider the impact of setting an initial condition λ∗(0) = λ0, perhaps in order to model
a process from some time after it is started. In this scenario the conditional intensity process (using
the exponential form of µ(·)) satisﬁes the stochastic diﬀerential equation
dλ∗(t) = β(λ −λ∗(t)) dt + α dN(t) ,
t ≥0 .
Applying stochastic calculus yields the general solution of
λ∗(t) = e−βt(λ0 −λ) + λ +
Z t
0
αeβ(t−s) dN(s) ,
t ≥0 ,
which is a natural extension of (4) [20].
3.3 Immigration–birth representation
Stability properties of the HP are often simpler to divine if it is viewed as a branching process.
Imagine counting the population in a country where people arrive either via immigration or by birth.
Say that the stream of immigrants to the country form a homogeneous Poisson process at rate λ.
Each individual then produces zero or more children independently of one another, and the arrival of
births form an inhomogeneous Poisson process.

Hawkes Processes
t
Fig. 4: Hawkes process represented as a collection of family trees (immigration–birth representation).
Squares (■) indicate immigrants, circles ( ) are oﬀspring/descendants, and the crosses (×) denote
the generated point process.
An illustration of this interpretation can be seen in Fig. 4. In branching theory terminology, this
immigration–birth representation describes a Galton–Watson process with a modiﬁed time dimension.
Hawkes [21] used the representation to derive asymptotic characteristics of the process, such as the
following result.
Theorem 1 (Hawkes process asymptotic normality) If
0 < n :=
Z ∞
0
µ(s) ds < 1 and
Z ∞
0
sµ(s) ds < ∞
then the number of HP arrivals in (0, t] is asymptotically (t →∞) normally distributed. More precisely,
writing N(0, t] = N(t) −N(0),
P
 
N(0, t] −λt/(1 −n)
p
λt/(1 −n)3
≤y
!
→Φ(y) ,
where Φ(·) is the c.d.f. of the standard normal distribution.
Remark 4 More modern work uses the immigration–birth representation for applying Bayesian tech-
niques; see, for example, [22].
For an individual who enters the system at time ti ∈R, the rate at which they produce oﬀspring
at future times t > ti is µ(t −ti). Say that the direct oﬀspring of this individual comprise the ﬁrst-
generation, and their oﬀspring comprise the second-generation, and so on; members of the union of all
these generations are called the descendants of this ti arrival.
Using the notation from [23, Section 5.4], deﬁne Zi to be the random number of oﬀspring in the ith
generation (with Z0 = 1). As the ﬁrst-generation oﬀspring arrived from a Poisson process Z1 ∼Poi(n)
where the mean n is known as the branching ratio. This branching ratio (which can take values in
(0, ∞)) is deﬁned in Theorem 1 and in the case of an exponentially decaying intensity is
n =
Z ∞
0
αe−βs ds = α
β .
(5)
Knowledge of the branching ratio can inform development of simulation algorithms. For each
immigrant i, the times of the ﬁrst-generation oﬀspring arrivals—conditioned on knowing the total
number of them Z1—are each i.i.d. with density µ(t−ti)/n. Section 6 explores HP simulation methods
inspired by the immigration–birth representation in more detail.

Patrick J. Laub et al.
The value of n also determines whether or not the HP explodes. To see this, let g(t) = E[λ∗(t)].
A renewal-type equation will be constructed for g and then its limiting value will be determined.
Conditioning on the time of the ﬁrst jump,
g(t) = E 
λ∗(t) = E
"
λ +
Z t
0
µ(t −s) dN(s)
#
= λ +
Z t
0
µ(t −s) E[dN(s)] .
In order to calculate this expected value, start with
λ∗(s) = lim
h↓0
E[N(s + h) −N(s) | H(s)]
h
= E[dN(s) | H(s)]
ds
and take expectations (and apply the tower property)
g(s) = E[λ∗(s)] = E[E[dN(s) | H(s)]]
ds
= E[dN(s)]
ds
to see that
E[dN(s)] = g(s) ds .
Therefore
g(t) = λ +
Z t
0
µ(t −s) g(s) ds = λ +
Z t
0
g(t −s) µ(s) ds .
This renewal–type equation (in convolution notation is g = λ + g ⋆µ) then has diﬀerent solutions
according to the value of n. Asmussen [24] splits the cases into: the defective case (n < 1), the proper
case (n = 1), and the excessive case (n > 1). Asmussen’s Proposition 7.4 states that for the defective
case
g(t) = E[λ∗(t)] →
λ
1 −n ,
as t →∞.
(6)
However in the excessive case, λ∗(t) →∞exponentially quickly, and hence N(·) eventually explodes
a.s.
Explosion for n > 1 is supported by viewing the arrivals as a branching process. Since E[Zi] = ni
(see Section 5.4 Lemma 2 of [23]), the expected number of descendants for one individual is
E


∞
X
i=1
Zi

=
∞
X
i=1
E[Zi] =
∞
X
i=1
ni =
(
n
1−n,
n < 1
∞,
n ≥1
.
Therefore n ≥1 means that one immigrant would generate inﬁnitely many descendants on average.
When n ∈(0, 1) the branching ratio can be interpreted as a probability. It is the ratio of the
number of descendants for one immigrant, to the size of their entire family (all descendants plus the
original immigrant); that is
E P∞
i=1 Zi

1 + E P∞
i=1 Zi
 =
n
1−n
1 +
n
1−n
=
n
1−n
1−n
= n .
Therefore, any HP arrival selected at random was generated endogenously (a child) with probability
(w.p.) n or exogenously (an immigrant) w.p. 1−n. Most properties of the HP rely on the process being
stationary, which is another way to insist that n ∈(0, 1) (a rigorous deﬁnition is given in Section 3.4),
so this is assumed hereinafter.

Hawkes Processes
3.4 Covariance and power spectral densities
HPs originated from the spectral analysis of general stationary point processes. The HP is stationary
for ﬁnite values of t when it is deﬁned as per Remark 2, so we will use this deﬁnition for the remainder
of Subsection 3.4. Finding the power spectral density of the HP gives access to many techniques
from the spectral analysis ﬁeld; for example, model ﬁtting can be achieved by using the observed
periodogram of a realisation. The power spectral density is deﬁned in terms of the covariance density.
Once again the exposition is simpliﬁed by using the shorthand that
dN(t) = lim
h↓0 N(t + h) −N(t) .
Unfortunately the term ‘stationary’ has many diﬀerent meanings in probability theory. In this
context the HP is stationary when the jump process (dN(t) : t ≥0)—which takes values in {0, 1}—is
weakly stationary. This means that E[dN(t)] and Cov(dN(t), dN(t+s)) do not depend on t. Stationarity
in this sense does not imply stationarity of N(·) or stationarity of the inter-arrival times [25]. One
consequence of stationarity is that λ∗(·) will have a long term mean (as given by (6))
λ∗:= E[λ∗(t)] = E[dN(t)]
dt
=
λ
1 −n .
(7)
The (auto)covariance density is deﬁned, for τ > 0, to be
R(τ) = Cov
dN(t)
dt
, dN(t + τ)
dτ

.
Due to the symmetry of covariance, R(−τ) = R(τ), however R(·) cannot be extended to the whole of R
because there is an atom at 0. For simple point processes E[(dN(t))2] = E[dN(t)] (since dN(t) ∈{0, 1})
therefore for τ = 0
E[(dN(t))2] = E[dN(t)] = λ∗dt .
The complete covariance density (complete in that its domain is all of R) is deﬁned as
R(c)(τ) = λ∗δ(τ) + R(τ)
(8)
where δ(·) is the Dirac delta function.
Remark 5 Typically R(0) is deﬁned such that R(c)(·) is everywhere continuous. Lewis [25, p. 357]
states that strictly speaking R(c)(·) “does not have a ‘value’ at τ = 0”. See [12,15], and [4] for further
details.
The corresponding power spectral density function is then
S(ω) := 1
2π
Z ∞
−∞
e−iτωR(c)(τ) dτ = 1
2π
"
λ∗+
Z ∞
−∞
e−iτωR(τ) dτ
#
.
(9)
Up to now the discussion (excluding the ﬁnal value of (7)) has considered general stationary point
processes. To apply the theory speciﬁcally to HPs we need the following result.

Patrick J. Laub et al.
Theorem 2 (Hawkes process power spectral density) Consider a HP with an exponentially decaying
intensity with α < β. The intensity process then has covariance density, for τ > 0,
R(τ) = αβλ(2β −α)
2(β −α)2
e−(β−α)τ .
Hence, its power spectral density is, ∀ω ∈R,
S(ω) =
λβ
2π(β −α)

1 +
α(2β −α)
(β −α)2 + ω2

.
Proof (Adapted from [4].) Consider the covariance density for τ ∈R \ {0}:
R(τ) = E
dN(t)
dt
dN(t + τ)
dτ

−λ∗2 .
(10)
Firstly note that, via the tower property,
E
dN(t)
dt
dN(t + τ)
dτ

= E
"
E
dN(t)
dt
dN(t + τ)
dτ



 H(t + τ)
#
= E
"
dN(t)
dt
E
dN(t + τ)
dτ



 H(t + τ)
#
= E
dN(t)
dt
λ∗(t + τ)

.
Hence (10) can be combined with (3) to see that R(τ) equals
E

dN(t)
dt
 
λ +
Z t+τ
−∞
µ(t + τ −s) dN(s)
!
−λ∗2,
which yields
R(τ) = λ∗µ(τ) +
Z τ
−∞
µ(τ −v)R(v) dv
= λ∗µ(τ) +
Z ∞
0
µ(τ + v)R(v) dv +
Z τ
0
µ(τ −v)R(v) dv .
(11)
Refer to Appendix A.1 for details; this is a Wiener–Hopf-type integral equation. Taking the Laplace
transform of (11) gives
L 
R(τ)	 (s) =
αλ∗(2β −α)
2(β −α)(s + β −α) .
Refer to Appendix A.2 for details. Note that (5) and (7) supply λ∗= βλ/(β −α), which implies that
L 
R(τ)	 (s) =
αβλ(2β −α)
2(β −α)2(s + β −α) .
Therefore,
R(τ) = L −1

αβλ(2β −α)
2(β −α)2(s + β −α)

= αβλ(2β −α)
2(β −α)2
e−(β−α)τ .

Hawkes Processes
The values of λ∗and L 
R(τ)	 (s) are then substituted into the deﬁnition given in (9):
S(ω) = 1
2π
"
λ∗+
Z ∞
−∞
e−iτωR(τ) dτ
#
= 1
2π

λ∗+
Z ∞
0
e−iτωR(τ) dτ +
Z ∞
0
eiτωR(τ) dτ

= 1
2π
h
λ∗+ L 
R(τ)	 (iω) + L 
R(τ)	 (−iω)
i
= 1
2π
"
λ∗+
αλ∗(2β −α)
2(β −α)(iω + β −α) +
αλ∗(2β −α)
2(β −α)(−iω + β −α)
#
=
λβ
2π(β −α)

1 +
α(2β −α)
(β −α)2 + ω2

.
Remark 6 The power spectral density appearing in Theorem 2 is a shifted scaled Cauchy p.d.f.
Remark 7 As R(·) is a real-valued symmetric function, its Fourier transform S(·) is also real-valued
and symmetric, that is,
S(ω) = 1
2π
"
λ∗+
Z ∞
−∞
e−iτωR(τ) dτ
#
= 1
2π
"
λ∗+
Z ∞
−∞
cos(τω)R(τ) dτ
#
,
and
S+(ω) := S(−ω) + S(ω) = 2S(ω) .
It is common that S+(·) is plotted instead of S(·), as in Section 4.5 of [15]; this is equivalent to
wrapping the negative frequencies over to the positive half-line.
3.5 Generalisations
The immigration–birth representation is useful both theoretically and practically. However it can only
be used to describe linear HPs. Br´emaud and Massouli´e [26] generalised the HP to its nonlinear form:
Deﬁnition 6 (Nonlinear Hawkes process) Consider a counting process with conditional intensity
function of the form
λ∗(t) = Ψ
 Z t
−∞
µ(t −s) N(ds)
!
where Ψ : R →[0, ∞), µ : (0, ∞) →R. Then N(·) is a nonlinear Hawkes process. Selecting Ψ(x) = λ + x
reduces N(·) to the linear HP of Deﬁnition 5.
Modern work on nonlinear HPs is much rarer than the original linear case (for simulation see
pp. 96–116 of [7], and associated theory in [27]). This is due to a combination of factors; ﬁrstly, the
generalisation was introduced relatively recently, and secondly, the increased complexity frustrates
even simple investigations.
Now to return to the extension mentioned earlier, that of a collection of self- and mutually-exciting
HPs. The processes being examined are collections of one-dimensional HPs which ‘excite’ themselves
and each other.

Patrick J. Laub et al.
Deﬁnition 7 (Mutually exciting Hawkes process) Consider a collection of m counting processes
{N1(·), . . . , Nm(·)} denoted N. Say {Ti,j : i ∈{1, . . . , m}, j ∈N} are the random arrival times for each
counting process (and ti,j for observed arrivals). If for each i = 1, . . . , m then Ni(·) has conditional
intensity of the form
λ∗
i (t) = λi +
m
X
j=1
Z t
−∞
µj(t −u) dNj(u)
(12)
for some λi > 0 and µi : (0, ∞) →[0, ∞), then N is called a mutually exciting Hawkes process.
When the excitation functions are set to be exponentially decaying, (12) can be written as
λ∗
i (t) = λi +
m
X
j=1
Z t
−∞
αi,je−βi,j(t−s) dNj(s) = λi +
m
X
j=1
X
tj,k<t
αi,je−βi,j(t−tj,k)
(13)
for non-negative constants {αi,j, βi,j : i, j = 1, . . . , m}.
Remark 8 There are models for HPs where the points themselves are multi-dimensional, for example,
spatial HPs or temporo-spatial HPs [2]. One should not confuse mutually exciting HPs with these
multi-dimensional HPs.
3.6 Financial applications
This section reviews primarily the work of A¨ıt-Sahalia, et al. [28] and Filimonov and Sornette [6].
It assumes the reader is familiar with mathematical ﬁnance and the use of stochastic diﬀerential
equations.
3.6.1 Financial contagion
We turn our attention to the moest recent applications of HPs. A major domain for self- and mutually-
exciting processes is ﬁnancial analysis. Frequently it is seen that large movements in a major stock
market propagate in foreign markets as a process called ﬁnancial contagion. Examples of this phe-
nomenon are clearly visible in historical series of asset prices; Fig. 5 illustrates one such case.
The ‘Hawkes diﬀusion model’ introduced by [28] is an attempt to extend previous models of stock
prices to include ﬁnancial contagion. Modern models for stock prices are typically built upon the model
popularised by [29] where the log returns on the stock follow geometric Brownian motion. Whilst this
seminal paper was lauded by the economics community, the model inadequately captured the ‘fat
tails’ of the return distribution and so was not commonly used by traders [30]. Merton [31] attempted
to incorporate heavy tails by including a Poisson jump process to model booms and crashes in the
stock returns; this model is often called Merton diﬀusion model. The Hawkes diﬀusion model extends
this model by replacing the Poisson jump process with a mutually-exciting HP, so that crashes can
self-excite and propagate in a market and between global markets.
The basic Hawkes diﬀusion model describes the log returns of m assets {X1(·), . . . , Xm(·)} where
each asset i = 1, . . . , m has associated expected return µi ∈R, constant volatility σi ∈R+, and standard
Brownian motion (W X
i (t) : t ≥0). The Brownian motions have constant correlation coeﬃcients
{ρi,j : i, j = 1, . . . , m}. Jumps are added by a self- and mutually-exciting HP (as per Deﬁnition 7 with
some selection of constants α·,· and β·,·) with stochastic jump sizes (Zi(t) : t ≥0). The asset dynamics
are then assumed to satisfy
dXi(t) = µi dt + σi dW X
i (t) + Zi(t) dNi(t) .

Hawkes Processes
The general Hawkes diﬀusion model replaces the constant volatilities with stochastic volatilities
{V1(·), . . . , Vm(·)} speciﬁed by the Heston model. Each asset i = 1, . . . , m has a: long-term mean
volatility θi > 0, rate of returning to this mean κi > 0, volatility of the volatility νi > 0, and standard
Brownian motion (W V
i (t) : t ≥0). Correlation between the W X
· (·)’s is optional, yet the eﬀect would
be dominated by the jump component. Then the full dynamics are captured by
dXi(t) = µi dt +
p
Vi(t) dW X
i (t) + Zi(t) dNi(t) ,
dVi(t) = κi(θi −Vi(t)) dt + νi
p
Vi(t) dW V
i (t) .
However the added realism of the Hawkes diﬀusion model comes at a high price. The constant
volatility model requires 5m+3m2 parameters to be ﬁt (assuming Zi(·) is characterised by two parame-
ters) and the stochastic volatility extension requires an extra 3m parameters (assuming ∀i, j = 1, . . . , m
that E[Wi(·)V Wj(·)V ] = 0). In [28] hypothesis tests reject the Merton diﬀusion model in favour of the
Hawkes diﬀusion model, however there are no tests for overﬁtting the data (for example, Akaike or
Bayesian information criterion comparisons). Remember that John Von Neumann (reputedly) claimed
that “with four parameters I can ﬁt an elephant” [32].
For computational necessity the authors made a number of simplifying assumptions to reduce
the number of parameters to ﬁt (such as the background intensity of crashes is the same for all
markets). Even so, the Hawkes diﬀusion model was only able to be ﬁtted for pairs of markets (m = 2)
instead of for the globe as a whole. Since the model was calibrated to daily returns of market indices,
historical data was easily available (for exmaple, from Google or Yahoo! ﬁnance); care had to be
taken to convert timezones and handle the diﬀerent market opening and closing times. The parameter
estimation method used by [28] was the generalised method of moments, however the theoretical
moments derived satisfy long and convoluted equations.
3.6.2 Mid-price changes and high-frequency trading
A simpler system to model is a single stock’s price over time, though there are many diﬀerent prices
to consider. For each stock one could use: the last transaction price, the best ask price, the best bid
price, or the mid-price (deﬁned as the average of best ask and best bid prices). The last transaction
price includes inherent microstructure noise (for example, the bid–ask bounce), and the best ask and
bid prices fail to represent the actions of both buyers and sellers in the market.
Filimonov and Sornette [6] model the mid-price changes over time as a HP. In particular they look
at long-term trends of the (estimated) branching ratio. In this context, n represents the proportion
of price moves that are not due to external market information but simply reactions to other market
participants. This ratio can be seen as the quantiﬁcation of the principle of economic reﬂexivity. The
authors conclude that the branching ratio has increased dramatically from 30% in 1998 to 70% in
2007.
Later that year [33] critiqued the test procedure used in this analysis. Filimonov and Sornette
[6] had worked with a dataset with timestamps accurate to a second, and this often led to multiple
arrivals nominally at the same time (which is an impossible event for simple point processes). Fake
precision was achieved by adding Unif(0, 1) random fractions of seconds to all timestamps, a technique
also used by [34]. Lorenzen found that this method added an element of smoothing to the data which
gave it a better ﬁt to the model than the actual millisecond precision data. The randomisation also
introduced bias to the HP parameter estimates, particularly of α and β. Lorenzen formed a crude
measure of high-frequency trading activity leading to an interesting correlation between this activity
and n over the observed period.

Patrick J. Laub et al.
Fig. 5: Example of mutual excitation in global markets. This ﬁgure plots the cascade of declines in
international equity markets experienced between October 3, 2008 and October 10, 2008 in the US;
Latin America (LA); UK; Developed European countries (EU); and Developed countries in the Paciﬁc.
Data are hourly. The ﬁrst observation of each price index series is normalised to 100 and the following
observations are normalised by the same factor. Source: MSCI MXRT international equity indices on
Bloomberg (reproduced from [28]).
Remark 9 Fortunately we have received comments from referees suggesting other very important works
to consider, which we will brieﬂy list here. The importance of Bowsher [34] is highlighted, as is the
series by Chavez-Demoulin et al. [35,36]. They point to the book by McNeil et al. [37] where a section
is devoted to HP applications, and stress the relevance of the Parisian school in applying HPs to
microstructure modelling, for example, the paper by Bacry et al. [38].
4 Parameter estimation
This section investigates the problem of generating parameters estimates bθ = (bλ, bα, bβ) given some
ﬁnite set of arrival times t = {t1, t2, . . . , tk} presumed to be from a HP. For brevity, the notation here
will omit the bθ and t arguments from functions:
L = L(bθ; t), l = l(bθ; t), λ∗(t) = λ∗(t; t, bθ), and
Λ(t) = Λ(t; t, bθ). The estimators are tested over simulated data, for the sake of simplicity and lack
of relevant data. Unfortunately this method bypasses the many signiﬁcant challenges raised by real
datasets, challenges that caused [39] to state that

Hawkes Processes
“Our overall conclusion is that calibrating the Hawkes process is akin to an excursion within a
mineﬁeld that requires expert and careful testing before any conclusive step can be taken.”
The method considered is maximum likelihood estimation, which begins by ﬁnding the likelihood
function, and estimates the model parameters as the inputs which maximise this function.
4.1 Likelihood function derivation
Daley and Vere-Jones [9, Proposition 7.2.III] give the following result.
Theorem 3 (Hawkes process likelihood) Let N(·) be a regular point process on [0, T] for some ﬁnite
positive T, and let t1, . . . , tk denote a realisation of N(·) over [0, T]. Then, the likelihood L of N(·) is
expressible in the form
L =
h
k
Y
i=1
λ∗(ti)
i
exp

−
Z T
0
λ∗(u) du

.
Proof First assume that the process is observed up to the time of the kth arrival. The joint density
function from (1) is
L = f(t1, t2, . . . , tk) =
k
Y
i=1
f∗(ti) .
This function can be written in terms of the conditional intensity function. Rearrange (2) to ﬁnd f∗(t)
in terms of λ∗(t) (as per [40]):
λ∗(t) =
f∗(t)
1 −F ∗(t) =
d
dtF ∗(t)
1 −F ∗(t) = −d log(1 −F ∗(t))
dt
.
Integrate both sides over the interval (tk, t):
−
Z t
tk
λ∗(u) du = log(1 −F ∗(t)) −log(1 −F ∗(tk)) .
The HP is a simple point process, meaning that multiple arrivals cannot occur at the same time.
Hence F ∗(tk) = 0 as Tk+1 > tk, and so
−
Z t
tk
λ∗(u) du = log(1 −F ∗(t)) .
(14)
Further rearranging yields
F ∗(t) = 1 −exp

−
Z t
tk
λ∗(u) du

,
f∗(t) = λ∗(t) exp

−
Z t
tk
λ∗(u) du

.
(15)
Thus the likelihood becomes
L =
k
Y
i=1
f∗(ti) =
k
Y
i=1
λ∗(ti) exp

−
Z ti
ti−1
λ∗(u) du

=
h
k
Y
i=1
λ∗(ti)
i
exp

−
Z tk
0
λ∗(u) du

.
(16)

Patrick J. Laub et al.
Now suppose that the process is observed over some time period [0, T] ⊃[0, tk]. The likelihood will
then include the probability of seeing no arrivals in the time interval (tk, T]:
L =
h
k
Y
i=1
f∗(ti)
i
(1 −F ∗(T)) .
Using the formulation of F ∗(t) from (15), then
L =
h
k
Y
i=1
λ∗(ti)
i
exp

−
Z T
0
λ∗(u) du

.
The completes the proof.
4.2 Simpliﬁcations for exponential decay
With the likelihood function from (16), the log-likelihood for the interval [0, tk] can be derived as
l =
k
X
i=1
log(λ∗(ti)) −
Z tk
0
λ∗(u) du =
k
X
i=1
log(λ∗(ti)) −Λ(tk) .
(17)
Note that the integral over [0, tk] can be broken up into the segments [0, t1], (t1, t2], . . . , (tk−1, tk], and
therefore
Λ(tk) =
Z tk
0
λ∗(u) du =
Z t1
0
λ∗(u) du +
k−1
X
i=1
Z ti+1
ti
λ∗(u) du .
This can be simpliﬁed in the case where λ∗(·) decays exponentially:
Λ(tk) =
Z t1
0
λ du +
k−1
X
i=1
Z ti+1
ti
λ +
X
tj<u
αe−β(u−tj) du
= λtk + α
k−1
X
i=1
Z ti+1
ti
i
X
j=1
e−β(u−tj) du
= λtk + α
k−1
X
i=1
i
X
j=1
Z ti+1
ti
e−β(u−tj) du
= λtk −α
β
k−1
X
i=1
i
X
j=1
h
e−β(ti+1−tj) −e−β(ti−tj)i
.
Finally, many of the terms of this double summation cancel out leaving
Λ(tk) = λtk −α
β
k−1
X
i=1
h
e−β(tk−ti) −e−β(ti−ti)i
= λtk −α
β
k
X
i=1
h
e−β(tk−ti) −1
i
.
(18)
Note that here the ﬁnal summand is unnecessary, though it is often included, see [33]. Substituting
λ∗(·) and Λ(·) into (17) gives
l =
k
X
i=1
log
h
λ + α
i−1
X
j=1
e−β(ti−tj)i
−λtk + α
β
k
X
i=1
h
e−β(tk−ti) −1
i
.
(19)

Hawkes Processes
This direct approach is computationally infeasible as the ﬁrst term’s double summation entails
O(k2) complexity. Fortunately the similar structure of the inner summations allows l to be computed
with O(k) complexity [41,42]. For i ∈{2, . . . , k}, let A(i) = Pi−1
j=1 e−β(ti−tj), so that
A(i) = e−βti+βti−1
i−1
X
j=1
e−βti−1+βtj = e−β(ti−ti−1)
1 +
i−2
X
j=1
e−β(ti−1−tj)
= e−β(ti−ti−1)(1 + A(i −1)) .
(20)
With the added base case of A(1) = 0, l can be rewritten as
l =
k
X
i=1
log(λ + αA(i)) −λtk + α
β
k
X
i=1
h
e−β(tk−ti) −1
i
.
(21)
Ozaki [8] also gives the partial derivatives and the Hessian for this log-likelihood function. Of
particular note is that each derivative calculation can be achieved in order O(k) complexity when a
recursive approach (similar to (20)) is taken [43].
Remark 10 The recursion implies that the joint process (N(t), λ∗(t)) is Markovian (see Remark 1.22
of [44]).
4.3 Discussion
Understanding of the maximum likelihood estimation method for the HP has changed signiﬁcantly
over time. The general form of the log-likelihood function (17) was known by Rubin [45]. It was applied
to the HP by Ozaki [8] who derived (19) and the improved recursive form (21). Ozaki also found (as
noted earlier) an eﬃcient method for calculating the derivatives and the Hessian matrix. Consistency,
asymptotic normality and eﬃciency of the estimator were proved by Ogata [41].
It is clear that the maximum likelihood estimation will usually be very eﬀective for model ﬁt-
ting. However, [6] found that, for small samples, the estimator produces signiﬁcant bias, encounters
many local optima, and is highly sensitive to the selection of excitation function. Additionally, the
O(k) complexity can render the method useless when samples become large; remember that any it-
erative optimisation routine would calculate the likelihood function perhaps thousands of times. The
R ‘hawkes’ package thus implements this routine in C++ in an attempt to mitigate the performance
issues.
This ‘performance bottleneck’ is largely the cause of the latest trend of using the generalised
method of moments to perform parameter estimation. Da Fonseca and Zaatour [20] state that the
procedure is “instantaneous” on their test sets. The method uses sample moments and the sample
autocorrelation function which are smoothed via a (rather arbitrary) user-selected procedure.
5 Goodness of ﬁt
This section outlines approaches to determining the appropriateness of a HPs model for point data,
which is a critical link in their application.

Patrick J. Laub et al.
5.1 Transformation to a Poisson process
Assessing the goodness of ﬁt for some point data to a Hawkes model is an important practical consid-
eration. In performing this assessment the point process’ compensator is essential, as is the random
time change theorem (here adapted from [46]):
Theorem 4 (Random time change theorem) Say {t1, t2, . . . , tk} is a realisation over time [0, T] from
a point process with conditional intensity function λ∗(·). If λ∗(·) is positive over [0, T] and Λ(T) < ∞a.s.
then the transformed points {Λ(t1), Λ(t2), . . . , Λ(tk)} form a Poisson process with unit rate.
The random time change theorem is fundamental to the model ﬁtting procedure called (point
process) residual analysis. Original work [47] on residual analysis goes back to [48], [49], and [50]. Daley
and Vere-Jones’s Proposition 7.4.IV [9] rewords and extends the theorem as follows.
Theorem 5 (Residual analysis) Consider an unbounded, increasing sequence of time points {t1, t2, . . . }
in the half-line (0, ∞), and a monotonic, continuous compensator Λ(·) such that limt→∞Λ(t) = ∞a.s.
The transformed sequence {t∗
1, t∗
2, . . . } = {Λ(t1), Λ(t2), . . . }, whose counting process is denoted N∗(t), is
a realisation of a unit rate Poisson process if and only if the original sequence {t1, t2, . . . } is a realisation
from the point process deﬁned by Λ(·).
Hence, equipped with a closed form of the compensator from (18), the quality of the statistical
inference can be ascertained using standard ﬁtness tests for Poisson processes. Fig. 6 shows a realisation
of a HP and the corresponding transformed process. In Fig. 6 Λ(t) appears identical to N(t). They are
actually slightly diﬀerent (Λ(·) is continuous) however the similarity is expected due to Doob–Meyer
decomposition of the compensator.
5.2 Tests for Poisson process
5.2.1 Basic tests
There are many procedures for testing whether a series of points form a Poisson process (see [15] for
an extensive treatment). As a ﬁrst test, one can run a hypothesis test to check P
i 1{t∗
i <t} ∼Poi(t).
If this initial test succeeds then the interarrival times,
{τ1, τ2, τ3, . . . } = {t∗
1, t∗
2 −t∗
1, t∗
3 −t∗
2, . . . },
should be tested to ensure τi
i.i.d.
∼Exp(1). A qualitative approach is to create a quantile–quantile (Q–Q)
plot for τi using the exponential distribution (see for example Fig. 7a). Otherwise a quantitative
alternative is to run Kolmogorov–Smirnov (or perhaps Anderson–Darling) tests.
5.2.2 Test for independence
The next test, after conﬁrming there is reason to believe that the τi are exponentially distributed,
is to check their independence. This can be done by looking for autocorrelation in the τi sequence.
Obviously zero autocorrelation does not imply independence, but a non-zero amount would certainly
imply a non-Poisson model. A visual examination can be conducted by plotting the points (Ui+1, Ui).
If there are noticeable patterns then the τi are autocorrelated. Otherwise the points should look evenly
scattered; see for example Fig. 7b. Quantitative extensions exist; for example see Section 3.3.3 of [51],
or serial correlation tests in [52].

Hawkes Processes
(a)
0
0
1,000
N(t)
E[N(t)]
(b)
0
0
λ∗(t)
E[λ∗(t)]
(c)
0
0
1,000
Λ(t)
(d)
0
1,000
N ∗(t)
E[N ∗(t)]
Fig. 6: An example of using the random time change theorem to transform a Hawkes process into a
unit rate Poisson process. (a) A Hawkes process N(t) with (λ, α, β) = (0.5, 2, 2.1), with the associated
(b) conditional intensity function and (c) compensator. (d) The transformed process N∗(t), where
t∗
i = Λ(ti).
5.2.3 Lewis test
A statistical test with more power is the Lewis test as described by [53]. Firstly, it relies on the fact
that if {t∗
1, t∗
2, . . . , t∗
N} are arrival times for a unit rate Poisson process then {t∗
1/t∗
N, t∗
2/t∗
N, . . . , t∗
N−1/t∗
N}
are distributed as the order statistics of a uniform [0, 1] random sample. This observation is called
conditional uniformity, and forms the basis for a test itself. Lewis’ test relies on applying Durbin’s
modiﬁcation (introduced in [54] with a widely applicable treatment by [55]).
5.2.4 Brownian motion approximation test
An approximate test for Poissonity can be constructed by using the Brownian motion approximation
to the Poisson process. This is to say, the observed times are transformed to be (approximately)
Brownian motion, and then known properties of Brownian motion sample paths can be used to accept
or reject the original sample.
The motivation for this line of enquiry comes from Algorithm 7.4.V of [9], which is described as
an “approximate Kolmogorov–Smirnov-type test”. Unfortunately, a typographical error causes the
algorithm (as printed) to produce incorrect answers for various signiﬁcance levels. An alternative test
based on the Brownian motion approximation is proposed here.
Say that N(t) is a Poisson process of rate T. Deﬁne M(t) = (N(t)−tT)/
√
T for t ∈[0, 1]. Donsker’s
invariance principle implies that, as T →∞, (M(t) : t ∈[0, 1]) converges in distribution to standard

Patrick J. Laub et al.
(a)
0
0
Expected
Observed
(b)
0
0.2
0.4
0.6
0.8
0
0.2
0.4
0.6
0.8
Uk
Uk+1
Fig. 7: (a) Q–Q testing for i.i.d. Exp(1) interarrival times. (b) A qualitative autocorrelation test. The
Uk values are deﬁned as Uk = F(t∗
k −t∗
k−1) = 1 −e−(t∗
k−t∗
k−1).
Brownian motion (B(t) : t ∈[0, 1]). Fig. 8 shows example realisations of M(t) for various T that, at
least qualitatively, are reasonable approximations to standard Brownian motion.
An alternative test is to utilise the ﬁrst arcsine law for Brownian motion, which states that the
random time M∗∈[0, 1], given by
M∗= arg max
s∈[0,1] B(s) ,
is arcsine distributed (that is, M∗∼Beta(1/2, 1/2)). Therefore the test takes a sequence of arrivals
observed over [0, T] and:
1. transforms the arrivals to {t∗
1/T, t∗
2/T, . . . , t∗
k/T} which should be a Poisson process with rate T
over [0, 1],
2. constructs the Brownian motion approximation M(t) as above, ﬁnds the maximiser M∗, and
3. accepts the ‘unit-rate Poisson process’ hypothesis if M∗lies within the (α/2, 1 −α/2) quantiles of
the Beta(1/2, 1/2) distribution; otherwise it is rejected.
As a ﬁnal note, many other tests can be performed based on other properties of Brownian motion.
For example, the test could be based simply on noting that M(1) ∼N(0, 1), and thus accepts if
M(1) ∈[Zα/2, Z1−α/2] and rejects otherwise.
6 Simulation methods
Simulation is an increasingly indispensable tool in probability modelling. Here we give details of three
fundamental approaches to producing realisations of HPs.
6.1 Transformation methods
For general point processes a simulation algorithm is suggested by the converse of the random time
change theorem (given in Section 5.1). In essence, a unit rate Poisson process {t∗
1, t∗
2, . . . } is transformed

Hawkes Processes
(a)
0
0.5
0
t
M(t)
(b)
0
0.5
0
t
M(t)
(c)
0
0.5
−2
0
t
M(t)
(d)
0
0.5
−2
0
t
B(t)
Fig. 8: Realisations of Poisson process approximations to Brownian motion. Plots (a)–(c) use the
observed windows of T =10, 100, and 10,000, respectively. Plot (d) is a direct simulation of Brownian
motion for comparison.
by the inverse compensator Λ(·)−1 into any general point process deﬁned by that compensator. The
method, sometimes called the inverse compensator method, iteratively solves the equations
t∗
1 =
Z t1
0
λ∗(s) ds,
t∗
k+1 −t∗
k =
Z tk+1
tk
λ∗(s) ds
for {t1, t2, . . . }, the desired point process (see [56] and Algorithm 7.4.III of [9]).
For HPs the algorithm was ﬁrst suggested by Ozaki [8], but did not state explicitly any relation
to time changes. It instead focused on (14),
Z t
tk
λ∗(u) du = −log(1 −F ∗(t)) ,
which relates the conditional c.d.f. of the next arrival to the previous history of arrivals {t1, t2, . . . , tk}
and the speciﬁed λ∗(t). This relation means the next arrival time Tk+1 can easily be generated by the
inverse transform method, that is draw U ∼Unif[0, 1] then tk+1 is found by solving
Z tk+1
tk
λ∗(u) du = −log(U) .
(22)
For an exponentially decaying intensity the equation becomes
log(U) + λ(tk+1 −tk) −α
β

k
X
i=1
e β(tk−1−ti) −
k
X
i=1
e−β(tk−ti)
= 0 .
Solving for tk+1 can be achieved in linear time using the recursion of (20). However if a diﬀerent
excitation function is used then (22) must be solved numerically, for example using Newton’s method
[43], which entails a signiﬁcant computational eﬀort.

Patrick J. Laub et al.
6.2 Ogata’s modiﬁed thinning algorithm
HP generation is a similar problem to inhomogeneous Poisson process generation. The standard way to
generate a inhomogeneous Poisson process driven by intensity function λ(·) is via thinning. Formally
the process is described by Algorithm 1 [57]. The intuition is to generate a ‘faster’ homogeneous
Poisson process, and remove points probabilistically so that the remaining points satisfy the time-
varying intensity λ(·). The ﬁrst process’ rate M cannot be less than λ(·) over [0, T].
A similar approach can be used for the HP, called Ogata’s modiﬁed thinning algorithm [43,44]. The
conditional intensity λ∗(·) does not have an a.s. asymptotic upper bound, however it is common for
the intensity to be non-increasing in periods without any arrivals. This implies that for t ∈(Ti, Ti+1],
λ∗(t) ≤λ∗(T +
i ) (that is, the time just after Ti, when that arrival has been registered). So the M
value can be updated during each simulation. Algorithm 2 describes the process and Fig. 9 shows an
example of each thinning procedure.
Algorithm 1 Generate an inhomogeneous Poisson process by thinning.
1: procedure PoissonByThinning(T, λ(·), M)
2:
require: λ(·) ≤M on [0, T]
3:
P ←[], t ←0.
4:
while t < T do
5:
E ←Exp(M).
6:
t ←t + E.
7:
U ←Unif(0, M).
8:
if t < T and U ≤λ(t) then
9:
P ←[P, t].
10:
end if
11:
end while
12:
return P
13: end procedure
Algorithm 2 Generate a Hawkes process by thinning.
1: procedure HawkesByThinning(T, λ∗(·))
2:
require: λ∗(·) non-increasing in periods of no arrivals.
3:
ε ←10−10 (some tiny value > 0).
4:
P ←[], t ←0.
5:
while t < T do
6:
Find new upper bound:
7:
M ←λ∗(t + ε).
8:
Generate next candidate point:
9:
E ←Exp(M), t ←t + E.
10:
Keep it with some probability:
11:
U ←Unif(0, M).
12:
if t < T and U ≤λ∗(t) then
13:
P ←[P, t].
14:
end if
15:
end while
16:
return P
17: end procedure

Hawkes Processes
(a)
0
0
t
U
λ(t)
M
Accepted
Rejected
(b)
0
0.5
1.5
2.5
3.5
0
t
U
λ∗(t)
M
Accepted
Rejected
Fig. 9: Processes generated by thinning. (a) A Poisson process with intensity λ(t) = 2+sin(t), bounded
above by M = 4. (b) A Hawkes process with (λ, α, β) = (1, 1, 1.1). Each (t, U) point describes a
suggested arrival at time t whose U value is given in Algorithm 1 and Algorithm 2. Plus signs indicate
rejected points, circles accepted, and green squares the resulting point processes.
6.3 Superposition of Poisson processes
The immigration–birth representation gives rise to a simple simulation procedure: generate the immi-
grant arrivals, then generate the descendants for each immigrant. Algorithm 3 describes the procedure
in full, with Fig. 10 showing an example realisation.
Immigrants form a homogeneous Poisson process of rate λ, so over an interval [0, T] the number of
immigrants is Poi(λT) distributed. Conditional on knowing that there are k immigrants, their arrival
times C1, C2, . . . , Ck are distributed as the order statistics of i.i.d. Unif[0, T] random variables.
Each immigrant’s descendants form an inhomogeneous Poisson process. The ith immigrant’s de-
scendants arrive with intensity µ(t −Ci) for t > Ci. Denote Di to be the number of descendants of
immigrant i, then E[Di] = R ∞
0
µ(s) ds = n, and hence Di
i.i.d.
∼Poi(n). Say that the descendants of the
ith immigrant arrive at times (Ci + E1, Ci + E2, . . . , Ci + EDi). Conditional on knowing Di, the Ej
are i.i.d. random variables distributed with p.d.f. µ(·)/n. For exponentially decaying intensities, this
simpliﬁes to Ej
i.i.d.
∼Exp(β).
6.4 Other methods
This section’s contents are by no means a complete compilation of simulation techniques available for
HPs. Dassios and Zhao [58] and Møller and Rasmussen [59] give alternatives to the methods listed
above. Also not discussed is the problem of simulating mutually-exciting HPs, however there are many

Patrick J. Laub et al.
Algorithm 3 Generate a Hawkes process by clusters.
1: procedure HawkesByClusters(T, λ, α, β)
2:
P ←{}.
3:
Immigrants:
4:
k ←Poi(λT)
5:
C1, C2, . . . , Ck
i.i.d.
←−Unif(0, T).
6:
Descendants:
7:
D1, D2, . . . , Dk
i.i.d.
←−Poi(α/β).
8:
for i ←1 to k do
9:
if Di > 0 then
10:
E1, E2, . . . , EDi
i.i.d.
←−Exp(β).
11:
P ←P ∪{Ci + E1, . . . , Ci + EDi}.
12:
end if
13:
end for
14:
Remove descendants outside [0, T]:
15:
P ←{Pi : Pi ∈P, Pi ≤T}.
16:
Add in immigrants and sort:
17:
P ←Sort(P ∪{C1, C2, . . . , Ck}).
18:
return P
19: end procedure
(a)
0
0
t
Family Number
(b)
0
0
t
Intensity
Fig. 10: A Hawkes Poisson process generated by clusters. Plot (a) shows the points generated by
the immigrant–birth representation; it can be seen as a sequence of vertically stacked ‘family trees’.
The immigrant points are plotted as squares, following circles of the same height and color are its
oﬀspring. The intensity function, with (λ, α, β) = (1, 2, 1.2), is plotted in (b). The resulting Hawkes
process arrivals are drawn as crosses on the axis.
free software packages that provide this functionality. Fig. 11 shows an example realisation generated
using the R package ‘hawkes’ (see also Roger D. Peng’s related R package ‘ptproc’).

Hawkes Processes
(a)
0
0
t
Counts
(b)
0
0
t
Intensity
Fig. 11: A pair of mutually exciting Hawkes processes. (a) The two counting processes N1(t) and N2(t)
with parameters: λ1 = λ2 = 1, α1,1 = α1,2 = α2,1 = α2,2 = 2, β1,1 = β1,2 = β2,1 = β2,2 = 8. (b) The
processes’ realised intensitites (note that λ∗
1(t) = λ∗
2(t) so only one is plotted).
7 Conclusion
HPs are fundamentally fascinating models of reality. Many of the standard probability models are
Markovian and hence disregard the history of the process. The HP is structured around the premise
that the history matters, which partly explains why they appear in such a broad range of applications.
If the exponentially decaying intensity can be utilised, then the joint process (N(·), λ∗(·)) satisﬁes
the Markov condition, and both processes exhibit amazing analytical tractability. Explosion is avoided
by ensuring that α < β. The covariance density is a simple symmetric scaled exponential curve, and the
power spectral density is a shifted scaled Cauchy p.d.f. The likelihood function and the compensator
are elegant, and eﬃcient to calculate using recursive structures. Exact simulation algorithms can
generate this type of HP with optimal eﬃciency. Many aspects of the HP remain obtainable with any
selection of excitation function; for example, the random time change theorem completely solves the
problem of testing the goodness of a model’s ﬁt.
The use of HPs in ﬁnance appears itself to have been a self-exciting process. A¨ıt-Sahalia et al.
[28], Filimonov and Sornette [6], and Da Fonseca and Zaatour [20] formed the primary sources for the
ﬁnancial part of Section 3; these papers are surprisingly recent (given the fact that the model was
introduced in 1971) and are representative of a current surge in HP research.
A Additional proof details
In this appendix, we collect additional detail elided from the proof of Theorem 2.

Patrick J. Laub et al.
A.1 Supplementary to Theorem 2 (part one)
R(τ) = E

dN(t)
dt
 
λ +
Z t+τ
−∞
µ(t + τ −s) dN(s)
!
−λ∗2
= λE
dN(t)
dt

+ E

dN(t)
dt
 Z t+τ
−∞
µ(t + τ −s) dN(s)
!
−λ∗2
= λλ∗+ E
"
dN(t)
dt
Z t+τ
−∞
µ(t + τ −s) dN(s)
#
−λ∗2.
Introduce a change of variable v = s −t and multiply by dv
dv :
R(τ) = λλ∗+ E
"Z τ
−∞
µ(τ −v) dN(t)
dt
dN(t + v)
dv
dv
#
−λ∗2 = λλ∗+
Z τ
−∞
µ(τ −v)E
dN(t)
dt
dN(t + v)
dv

dv −λ∗2.
The expectation is (a shifted) R(c)(v). Substitute that and (8) in:
R(τ) = λλ∗+
Z τ
−∞
µ(τ −v)
 R(c)(v) + λ∗2
dv −λ∗2
= λλ∗+
Z τ
−∞
µ(τ −v)

λ∗δ(v) + R(v)

dv + λ∗2 Z τ
−∞
µ(τ −v) dv −λ∗2
= λλ∗+ λ∗µ(τ) +
Z τ
−∞
µ(τ −v)R(v) dv + nλ∗2 −λ∗2
= λ∗µ(τ) +
Z τ
−∞
µ(τ −v)R(v) dv + λ∗(λ −(1 −n)λ∗) .
Using (7) yields
λ −(1 −n)λ∗= λ −(1 −n)
λ
1 −n = 0 .
∴R(τ) = λ∗µ(τ) +
Z τ
−∞
µ(τ −v)R(v) dv .
A.2 Supplementary to Theorem 2 (part two)
Split the right-hand side of the equation into three functions g1, g2, and g3:
R(τ) = λ∗µ(τ)
| {z }
g1(τ)
+
Z ∞
0
µ(τ + v)R(v) dv
|
{z
}
g2(τ)
+
Z τ
0
µ(τ −v)R(v) dv
|
{z
}
g3(τ)
.
(23)
Taking the Laplace transform of each term gives
L

g1(τ)
	
(s) =
Z s
0
e−sτλ∗αe−βτ dτ =
α
s + β λ∗,
L

g2(τ)
	
(s) =
Z ∞
0
e−sτ
Z ∞
0
αe−β(τ+v)R(v) dv dτ
= α
Z ∞
0
e−βvR(v)
Z ∞
0
e−τ(s+β) dτ dv
=
α
s + β
Z ∞
0
e−βvR(v) dv
=
α
s + β L {R} (β) ,

Hawkes Processes
and
L

g3(τ)
	
(s) = L

µ(τ)
	
(s)L

R(τ)
	
(s) =
α
s + β L

R(τ)
	
(s) .
Therefore the Laplace transform of (23)
L

R(τ)
	
(s) =
α
s + β

λ∗+ L

R(τ)
	
(β) + L

R(τ)
	
(s)

.
(24)
Substituting s = β and rearranging gives that
L

R(τ)
	
(β) =
αλ∗
2(β −α) .
(25)
So substituting the value of L

R(τ)
	
(β) into (24) means
L

R(τ)
	
(s) =
α
s + β

λ∗+
αλ∗
2(β −α) + L

R(τ)
	
(s)

⇒L

R(τ)
	
(s) =
α
s+β

λ∗+
αλ∗
2(β−α)

1 −
α
s+β
=
αλ∗(2β −α)
2(β −α)(s + β −α) .
References
1. Y. Ogata, Journal of the American Statistical Association 83(401), 9 (1988)
2. G.O. Mohler, M.B. Short, P.J. Brantingham, F.P. Schoenberg, G.E. Tita, Journal of the American Statistical
Association 106(493), 100 (2011)
3. S. Azizpour, K. Giesecke, G. Schwenkler. Exploring the sources of default clustering. http://web.stanford.edu/
dept/MSandE/cgi-bin/people/faculty/giesecke/pdfs/exploring.pdf (2010). Working paper, retrieved on 10
Feb 2015
4. A.G. Hawkes, Biometrika 58(1), 83 (1971)
5. D. Lando, M.S. Nielsen, Journal of Financial Intermediation 19(3), 355 (2010)
6. V. Filimonov, D. Sornette, Physical Review E 85(5), 056108 (2012)
7. L. Carstensen, Hawkes processes and combinatorial transcriptional regulation. Ph.D. thesis, University of Copen-
hagen (2010)
8. T. Ozaki, Annals of the Institute of Statistical Mathematics 31(1), 145 (1979)
9. D. Daley, D. Vere-Jones, An Introduction to the Theory of Point Processes: Volume I: Elementary Theory and
Methods (Springer, 2003)
10. D.R. Cox, Journal of the Royal Statistical Society. Series B (Methodological) 17(2), 129 (1955)
11. M.S. Bartlett, Journal of the Royal Statistical Society. Series B (Methodological) 25(2), 264 (1963)
12. M.S. Bartlett, Sankhy¯a: The Indian Journal of Statistics, Series A 25(3), 245 (1963)
13. M.S. Bartlett, Biometrika 51(3/4), 299 (1964)
14. P.A. Lewis, Journal of the Royal Statistical Society. Series B (Methodological) 26(3), 398 (1964)
15. D.R. Cox, P.A. Lewis, The Statistical Analysis of Series of Events (Monographs on Applied Probability and
Statistics, London: Chapman and Hall, 1966)
16. A.G. Hawkes, Journal of the Royal Statistical Society. Series B (Methodological) 33(3), 438 (1971)
17. N. Hautsch, Econometrics of Financial High-Frequency Data (Springer, 2011)
18. Y. Ogata, Pure and Applied Geophysics 155(2/4), 471 (1999)
19. V. Chatalbashev, Y. Liang, A. Oﬃcer, N. Trichakis.
Exciting times for trade arrivals.
http://users.iems.
northwestern.edu/~armbruster/2007msande444/report1a.pdf (2007).
Stanford University MS&E 444 group
project submission, retrieved on 10 Feb 2015
20. J. Da Fonseca, R. Zaatour, Journal of Futures Markets 34(6), 548 (2014)
21. A.G. Hawkes, D. Oakes, Journal of Applied Probability 11(3), 493 (1974)
22. J.G. Rasmussen, Methodology and Computing in Applied Probability 15(3), 623 (2013)
23. G. Grimmett, D. Stirzaker, Probability and Random Processes (Oxford University Press, 2001)
24. S. Asmussen, Applied Probability and Queues, 2nd edn. Applications of Mathematics: Stochastic Modelling and
Applied Probability (Springer, 2003)
25. P.A. Lewis, Journal of Sound and Vibration 12(3), 353 (1970)
26. P. Br´emaud, L. Massouli´e, The Annals of Probability 24(3), 1563 (1996)

Patrick J. Laub et al.
27. L. Zhu, Journal of Applied Probability 50(3), 760 (2013)
28. Y. A¨ıt-Sahalia, J. Cacho-Diaz, R.J. Laeven, Modeling ﬁnancial contagion using mutually exciting jump processes.
Tech. Rep. 15850, National Bureau of Economic Research, USA (2010)
29. F. Black, M. Scholes, The Journal of Political Economy 81(3), 637 (1973)
30. E.G. Haug, N.N. Taleb, Wilmott Magazine 71 (2014)
31. R.C. Merton, Journal of Financial Economics 3(1), 125 (1976)
32. F. Dyson, Nature 427(6972), 297 (2004)
33. F. Lorenzen, Analysis of order clustering using high frequency data: A point process approach. Ph.D. thesis,
Swiss Federal Institute of Technology Zurich (ETH Zurich) (2012)
34. C.G. Bowsher, Journal of Econometrics 141(2), 876 (2007)
35. V. Chavez-Demoulin, A.C. Davison, A.J. McNeil, Quantitative Finance 5(2), 227 (2005)
36. V. Chavez-Demoulin, J. McGill, Journal of Banking & Finance 36(12), 3415 (2012)
37. A.J. McNeil, R. Frey, P. Embrechts, Quantitative Risk Management: Concepts, Techniques and Tools: Concepts,
Techniques and Tools (Princeton university press, 2015)
38. E. Bacry, S. Delattre, M. Hoﬀmann, J.F. Muzy, Quantitative Finance 13(1), 65 (2013)
39. V. Filimonov, D. Sornette, Apparent criticality and calibration issues in the Hawkes self-excited point process
model: application to high-frequency ﬁnancial data. Tech. Rep. 13-60, Swiss Finance Institute Research Paper
(2013)
40. J.G. Rasmussen. Temporal point processes: the conditional intensity function. http://people.math.aau.dk/
~jgr/teaching/punktproc11/tpp.pdf (2009). Course notes for ‘rumlige punktprocesser’ (spatial point processes),
retrieved on 10 Feb 2015
41. Y. Ogata, Annals of the Institute of Statistical Mathematics 30(1), 243 (1978)
42. S. Crowley. Point process models for multivariate high-frequency irregularly spaced data. http://vixra.org/
pdf/1211.0094v6.pdf (2013). Working paper, retrieved on 10 Feb 2015
43. Y. Ogata, Information Theory, IEEE Transactions on 27(1), 23 (1981)
44. T.J. Liniger, Multivariate Hawkes processes. Ph.D. thesis, Swiss Federal Institute of Technology Zurich (ETH
Zurich) (2009)
45. I. Rubin, Information Theory, IEEE Transactions on 18(5), 547 (1972)
46. E. Brown, R. Barbieri, V. Ventura, R. Kass, L. Frank, Neural computation 14(2), 325 (2002)
47. P. Embrechts, T. Liniger, L. Lin, Journal of Applied Probability 48A, 367 (2011). Special volume: a Festschrift
for Søren Asmussen
48. P.A. Meyer, in S´eminaire de Probabilit´es V Universit´e de Strasbourg (Springer, 1971), pp. 191–195
49. F. Papangelou, Transactions of the American Mathematical Society 165, 483 (1972)
50. S. Watanabe, Japan. J. Math 34(53-70), 82 (1964)
51. D.E. Knuth, Art of Computer Programming, Volume 2: Seminumerical Algorithms, The (Addison-Wesley Pro-
fessional, 2014)
52. D. Kroese, T. Taimre, Z.I. Botev, Handbook of Monte Carlo methods (Wiley, 2011)
53. S.H. Kim, W. Whitt, The power of alternative Kolmogorov–Smirnov tests based on transformations of the data
(2013). Submitted to ACM Transactions on Modeling and Computer Simulation, Special Issue in Honor of Don
Iglehart (Issue 25.4)
54. J. Durbin, Biometrika 53(3/4), 41 (1961)
55. P.A. Lewis, Biometrika 52(1/2), 67 (1965)
56. K. Giesecke, P. Tomecek.
Dependent events and changes of time.
http://web.stanford.edu/dept/MSandE/
cgi-bin/people/faculty/giesecke/pdfs/dect.pdf (2005). Working paper, retrieved on 10 Feb 2015
57. P.A. Lewis, G.S. Shedler, Naval Research Logistics Quarterly 26(3), 403 (1979)
58. A. Dassios, H. Zhao, Electronic Communications in Probability 18(62) (2013)
59. J. Møller, J.G. Rasmussen, Advances in Applied Probability 37(3), 629 (2005)