
# TABLE OF CONTENTS

|  Sr. No. | Unit | Page No.  |
| --- | --- | --- |
|  1 | Complex Numbers | 1  |
|  2 | Functions and Graphs | 22  |
|  3 | Theory of Quadratic Functions | 34  |
|  4 | Matrices and Determinants | 44  |
|  5 | Partial Fractions | 78  |
|  6 | Sequences and Series | 88  |
|  7 | Permutations and Combinations | 123  |
|  8 | Mathematical Inductions and Binomial Theorem | 140  |
|  9 | Division of Polynomials | 169  |
|  10 | Trigonometric Identities | 177  |
|  11 | Trigonometric Functions and their Graphs | 200  |
|  12 | Limit and Continuity | 218  |
|  13 | Differentiation | 237  |
|  14 | Vectors in Space | 258  |
|   | Answers | 291  |

# Complex Numbers 

## INTRODUCTION

Complex numbers are an extension of the real numbers designed to solve equations that have no solutions within the realm of real numbers. The history of mathematics shows that man has been developing and enlarging his concept of number according to the saying that "Necessity is the mother of invention". In the remote past they started with the set of counting numbers and invented, by stages, the negative numbers, rational numbers, irrational numbers etc. Since square of a positive as well as negative number is a positive number, the square root of a negative number does not exist in the realm of real numbers. Therefore, square roots of negative numbers were given no attention for centuries together. However, recently, properties of numbers involving square roots of negative numbers have also been discussed in detail and such numbers have been found useful and have been applied in many branches of pure, applied, financial and computational mathematics.

### 1.1 Complex Numbers

The numbers of the form $z=a+i b$, where $a, b \in R$ and $i=\sqrt{-1}$, are called complex numbers. For example, $3+4 i, 2 \frac{5}{7} i,-7-2 i$ etc. are complex numbers and the set of all complex numbers is denoted by $C$.

### 1.1.1 Recognition of Real and Imaginary Parts

Let us start with considering the following equation:

$$
x^{2}+1 \Rightarrow x^{2}=-1 \Rightarrow x= \pm \sqrt{-1}
$$

$\sqrt{-1}$ does not belong to the set of real numbers. We, therefore, for convenience call it imaginary number and denote it by $i$ (read as iota).

## Note

Every real number is a complex number with 0 as its imaginary part.

In the complex number $z=a+i b, a$ is called real part and $b$ is called imaginary part of the complex number. For convenient, real part is denoted by $\operatorname{Re} z$ and imaginary part by $\operatorname{Im} z$ of a complex number $z$. For example, if $z=3+4 i$, then

$$
\operatorname{Re} z=3 \text { and } \operatorname{Im} z=4
$$

The product of a non-zero real number and $i$ is also an imaginary number.
For example, $2 i,-3 i, \sqrt{5} i,-\frac{11}{2} i$ are all imaginary numbers.

Conjugate of Complex Numbers: Let $z=a+i b$ be a complex number, then $a-i b$ is called the complex conjugate of $a+i b$. It is denoted by $\bar{z}$. Thus $5-4 i$ is complex conjugate of $5+4 i$ and $-2-3 i$ is complex conjugate of $-2+3 i$.

# Note A real number is self-conjugate. 

### 1.1.2 Operations on Complex Numbers

With a view to develop algebra of complex numbers, we state a few definitions.
The symbols $a, b, c, d, k$, where used, represent real numbers.
(i) Addition: $(a+i b)+(c+i d)=(a+c)+i(b+d)$
(ii) $k(a+i b)=k a+i k b$
(iii) Subtraction: $(a+i b)-(c+i d)=(a+i b)+[-(c+i d)]$

$$
=a+i b+(-c-i d)=(a-c)+i(b-d)
$$

(iv) Multiplication: $(a+i b)(c+i d)=a c+i a d+i b c+i^{2} b d=(a c-b d)+i(a d+b c)$

### 1.1.3 Complex Numbers as Ordered Pairs of Real Numbers

We can define complex numbers also by using ordered pairs.
Let $C$ be the set of ordered pairs belonging to $R \times R$ which are subject to the following properties:
(i) $(a, b)=(c, d) \Leftrightarrow a=c \wedge b=d$
(ii) $(a, b)+(c, d)=(a+c, b+d)$
(iii) $(a, b)(c, d)=(a c-b d, a d+b c)$
(iv) If $k$ is any real number, then $k(a, b)=(k a, k b)$

Then $C$ is called the set of complex numbers. It is easy to see that

$$
(a, b)-(c, d)=(a-c, b-d)
$$

Properties (i), (ii) and (iii) respectively define equality, sum and product of two complex numbers. Property (iv) defines the product of a real number and a complex number.
Example 1 Find the sum, difference and product of the complex numbers $(8,9)$ and $(5,-6)$
Solution $\operatorname{Sum}=(8+5,9-6)=(13,3)$
Difference $=(8-5,9-(-6))=(3,15)$

$$
\begin{aligned}
\text { Product } & =(8.5-9(-6), 8(-6)+9.5) \\
& =(40+54,-48+45)=(94,-3)
\end{aligned}
$$

# 1.1.4 Properties of the Fundamental Operations on Complex Numbers 

It can be easily verified that the set $C$ satisfies all the field axioms i.e., it possesses the properties of real numbers.
By way of explanation of some points we observe as follows:
(i) The additive identity in $C$ is $(0,0)$.
(ii) Every complex number $(a, b)$ has the additive inverse $(-a,-b)$ i.e., $(a, b)+(-a,-b)=(0,0)$
(iii) The multiplicative identity is $(1,0)$ i.e.,

$$
\begin{aligned}
(a, b) \cdot(1,0) & =(\alpha \cdot 1-b \cdot 0, b \cdot 1+\alpha \cdot 0)=(a, b) \\
& =(1,0) \cdot(a, b)
\end{aligned}
$$

(iv) Every non-zero complex number \{i.e., number not equal to $(0,0)\}$ has a multiplicative inverse. The multiplicative inverse of $(a, b)$ is

$$
\left(\frac{a}{a^{2}+b^{2}}, \frac{-b}{a^{2}+b^{2}}\right)
$$

$\because \quad(a, b)\left(\frac{a}{a^{2}+b^{2}}, \frac{-b}{a^{2}+b^{2}}\right)=(1,0)$, the identity element

$$
=\left(\frac{a}{a^{2}+b^{2}}, \frac{-b}{a^{2}+b^{2}}\right)(a, b)
$$

(v) $(a, b)[(c, d) \pm(e, f)]=(a, b)\left(c, d\right) \pm(a, b)(e, f)$

Example 2 If $z_{1}=(4,2)$ and $z_{2}=(3,-1)$, then find $\frac{z_{1}}{z_{2}}$.
Solution Given $z_{1}=(4,2), z_{2}=(3,-1)$
Now, $\frac{z_{1}}{z_{2}}=\frac{(4,2)}{(3,-1)}=\frac{4+2 i}{3-i}$
Multiply the numerator and denominator by the complex conjugate of $z_{2}=3-i$.

$$
\begin{aligned}
\frac{z_{1}}{z_{2}} & =\frac{4+2 i}{3-i}=\frac{4+2 i}{3-i} \times \frac{3+i}{3+i} \\
& =\frac{(4)(3)+(4)(i)+(2 i)(3)+(2 i)(i)}{(3)^{2}-(i)^{2}}=\frac{12+4 i+6 i+2 i^{2}}{9-i^{2}} \\
& =\frac{12+10 i-2}{9-(-1)}=\frac{10+10 i}{10}=1+i \quad \because \quad i^{2}=-1
\end{aligned}
$$

Thus, $\frac{z_{1}}{z_{2}}=1+i$

# 1.1.5 Argand Diagram 

Every complex number is represented by one and only one point of the coordinate plane and every point of the plane represents one and only one complex number. The components of the complex number are be the coordinates of the point representing it. In this representation the $x$-axis is called the real axis and the $y$-axis is called the imaginary axis. The coordinate plane itself is called the complex plane or $z$ - plane. The figure representing one or more complex numbers on the complex plane is called an Argand diagram. The Argand diagram is a way of representing one or more complex numbers on the complex plane. Points on the $x$-axis represent real numbers whereas the points on the $y$-axis represent imaginary numbers.
[Image removed]

In an Argand diagram, the complex number $x+i y$ is uniquely represented by the order pair $(x, y)$. In Figure (i), the complex numbers $3+2 i,-2+2 i,-3-2 i$ and $2-2 i$ correspond to the order pairs $(3,2),(-2,2),(-3,-2)$ and $(2,-2)$ respectively have been represented geometrically by the point $A, B, C$ and $D$.
Modulus of a Complex Number: The real number $\sqrt{x^{2}+y^{2}}$ is called the modulus of the complex number $x+i y$ and it is denoted by $|x+i y|$. In Figure (ii), $O A$ represents the modulus of $x+i y$. In other words, the modulus of a complex number is the distance from the origin to the point representing the number.
[Image removed]
[Image removed]

Figure (ii)

$$
\begin{aligned}
z & =\frac{(1+2 i)^{2}}{2-i}=\frac{1+4 i+4 i^{2}}{2-i}=\frac{-3+4 i}{2-i} \times \frac{2+i}{2+i}=\frac{-6-3 i+8 i+4 i^{2}}{2^{2}-i^{2}} \\
& =\frac{-6+5 i-4}{4-(-1)}=\frac{-10+5 i}{5} \\
\Rightarrow \quad z & =-2+i
\end{aligned}
$$

Taking conjugate

$$
\bar{z}=\overline{-2+i}=-2-i
$$

$$
\begin{array}{ll}
\text { and } & |\bar{z}|=|-2-i|=\sqrt{(-2)^{2}+(-1)^{2}}=\sqrt{4+1} \\
\Rightarrow & |\bar{z}|=\sqrt{5}
\end{array}
$$

# EXERCISE 1.1 

1. Find the multiplicative inverse of each of the following complex numbers:
(i) $(-4,7)$
(ii) $(\sqrt{2},-\sqrt{5})$
(iii) $(1,0)$
2. Separate into real and imaginary parts (write as a simple complex number):
(i) $\frac{2-7 i}{4+5 i}$
(ii) $\frac{(-2+3 i)^{2}}{1+i}$
(iii) $\frac{i}{1+i}$
(iv) $\frac{(4+3 i)^{2}}{4-3 i}$
3. Prove that $\bar{z}=z$ iff $z$ is real.
4. For $z \in C$, show that:
(i) $\frac{z+\bar{z}}{2}=\operatorname{Re}(z)$
(ii) $\frac{z-\bar{z}}{2 i}=\operatorname{Im}(z)$
(iii) $|z|^{2}=z \cdot \bar{z}$
5. If $z_{1}=2+i, z_{2}=3-2 i, z_{3}=1+3 i$, then express $\frac{z_{1} z_{3}}{z_{2}}$ in the form of $a+i b$.
6. If $z_{1}=2+7 i$ and $z_{2}=-5+3 i$, then evaluate the following:
(i) $\left|2 z_{1}-4 z_{2}\right|$
(ii) $\left|3 z_{1}+2 z_{1}\right|$
(iii) $\left|-7 z_{2}+2 z_{2}\right|$
(iv) $\left|\left(z_{1}+z_{2}\right)^{3}\right|$
7. Show that: $i^{n+1}+i^{n+2} \in i^{n+3}+i^{n+4}=0$, for all $n \in N$.
8. Find the least positive value of $n$, if $\left(\frac{1+i}{1-i}\right)^{n}=1$
9. Show that: the value of $i^{n}$ for $n \in N$ and $n>4$ is $i^{r}$, where $r$ is the remainder when $n$ is divided by 4 .

### 1.2 Equality of Two Complex Numbers

The two complex numbers $z_{1}=a+b i$ and $z_{2}=c+d i$ are said to be equal iff their real and imaginary parts are equal i.e., $a+b i=c+d i \Leftrightarrow a=c$ and $b=d$.
Example 4 If $(3+2 i)(x+i y)=5+12 i$, where $x, y \in R$, then find the values of $x$ and $y$.
Solution Given that

$$
(3+2 i)(x+i y)=5+12 i
$$

$$
\begin{aligned}
& \Rightarrow 3 x+3 i y+2 i x+2 i^{2} y=5+12 i \\
& \Rightarrow(3 x-2 y)+(2 x+3 y) i=5+12 i
\end{aligned}
$$

Comparing real and imaginary parts, we have

$$
\begin{aligned}
& 3 x-2 y=5 \\
& 2 x+3 y=12
\end{aligned}
$$

Multiply equation (i) by 3 and equation (ii) by 2 , we have

$$
\begin{aligned}
& 9 x-6 y=15 \\
& 4 x+6 y=24
\end{aligned}
$$

Add the equations

$$
\begin{aligned}
9 x-6 y+4 x+6 y & =15+24 \\
13 x & =39 \\
x & =3
\end{aligned}
$$

Substitute $x=3$ in equation (i), we have

$$
\begin{aligned}
3(3)-2 y & =5 \\
9-2 y & =5 \\
-2 y & =-4 \\
y & =2
\end{aligned}
$$

Thus $x=3, y=2$

# 1.2.1 Square Root of a Complex Number 

The square root of a complex number is another complex number that, when squared, gives the original complex number.
Let $w=p+i q$ is a square root of a complex number $z=x+i y$, where $p, q, x, y \in R$, then $w=\sqrt{z} \ldots$ (i), taking square on both sides, we get

$$
\begin{aligned}
w^{2} & =z \\
(p+i q)^{2} & =x+i y \\
p^{2}+2 p q i-q^{2} & =x+i y
\end{aligned}
$$

Equating real and imaginary parts, we have

$$
\begin{aligned}
& x=p^{2}-q^{2} \\
& y=2 p q
\end{aligned}
$$

We know that $\left(p^{2}+q^{2}\right)^{2}=\left(p^{2}-q^{2}\right)^{2}+4 p^{2} q^{2}$
Substitute $x=p^{2}-q^{2}, y=2 p q$ in the above equation, we get

$$
\begin{aligned}
\left(p^{2}+q^{2}\right)^{2} & =x^{2}+y^{2} \\
\Rightarrow \quad p^{2}+q^{2} & =\sqrt{x^{2}+y^{2}}
\end{aligned}
$$

From equations (ii) and (iv), we have $x=p^{2}-q^{2}$ and $p^{2}+q^{2}=\sqrt{x^{2}+y^{2}}$. Solving for the values $p$ and $q$, we have

$$
p= \pm \sqrt{\frac{\sqrt{x^{2}+y^{2}}+x}{2}} \text { and } q= \pm \sqrt{\frac{\sqrt{x^{2}+y^{2}}-x}{2}}
$$

From equation (iii): $y=2 p q$, we have

- $y>0$, if $p$ and $q$ have the same sign
- $y<0$, if $p$ and $q$ have opposite signs
- $y=0$, if $p=0$ or $q=0$

Therefore, the square root of the complex number $z=x+i y$ is given by

$$
\sqrt{z}=\sqrt{x+i y}= \pm\left(\sqrt{\frac{\sqrt{x^{2}+y^{2}}+x}{2}}+\frac{i y}{|y|} \sqrt{\frac{\sqrt{x^{2}+y^{2}}-x}{2}}\right)
$$

or $\sqrt{x}= \pm\left(\sqrt{\frac{|z|+x}{2}}+\frac{i y}{|y|} \sqrt{\frac{|z|-x}{2}}\right) \cdots(\mathrm{v})$, where $|z|=\sqrt{x^{2}+y^{2}} \geq 0$ is modulus of $z$.
Equation (v) is the required formula for square root of the complex number $x+i y$.
Example 5 Find the square root of complex number $5+12 i$ and also represent the square root on an Argand diagram.
Solution Let $x+y i=5+12 i$

$$
\begin{aligned}
\Rightarrow \quad x & =5 \text { and } y=12>0 \\
|z| & =|5+12 i|=\sqrt{5^{2}+12^{2}}=13
\end{aligned}
$$

Applying the square root formula for complex numbers, we get

$$
\begin{aligned}
\sqrt{5+12 i} & = \pm\left(\sqrt{\frac{13+5}{2}}+\frac{12 i}{12} \sqrt{\frac{13-5}{2}}\right) \\
& = \pm(\sqrt{9}+i \sqrt{4})= \pm(3+2 i)
\end{aligned}
$$

[Image removed]

Thus, the square root of the complex number $5+12 i$ are $3+2 i$ and $-3-2 i$ as shown in above figure.

# EXERCISE 1.2 

1. Find the real values of $x$ and $y$ in each of the following:
(i) $x+i y+2-3 i=i(5-i)(3+4 i)$
(ii) $(x+i y)(1-i)=(2-3 i)(-5+5 i)\left(-i \frac{3}{5}\right)$
(iii) $\frac{x}{2+i}+\frac{y}{3-i}=4+5 i$

2. If $z_{1}=-13+24 i$ and $z_{2}=x+y i$, find the real values of $x$ and $y$ such that $z_{1}-z_{2}=-27+15 i$
3. Find the real values of $x$ and $y$ if:
(i) $(x+i y)^{2}=25+60 i$
(ii) $(x+i y)^{2}=64+48 i$
(iii) $(x+i y)^{2}=\frac{2 i-3}{3+i}$
4. If $z_{1}=2+3 i$ and $z_{2}=1-\alpha$, find the real value of $\alpha$ such that $\operatorname{Im}\left(z_{1} z_{2}\right)=7$.
5. If $z_{1}=x+y i$ and $z_{2}=a+b i$, find $x, y, a$ and $b$ such that $z_{1}+z_{2}=10+4 i$ and $z_{1}-z_{2}=6+2 i$.
6. Show that $\forall z_{1}, z_{2} \in C, \overline{z_{1} z_{2}}=\overline{z_{1} z_{2}}$
7. Find the square root of the following complex numbers:
(i) $-7-24 i$
(ii) $8-6 i$
(iii) $-15-36 i$
(iv) $119+120 i$
8. Find the square root of $13-20 \sqrt{3}$ and represent $1 / 3$ on an Argand diagram.
9. Find the real values of $x$ and $y$ if $(-7+i)(x+i y)+(-1-5 i)=i(11-i)$
10. Find the real values of $x$ and $y$ if $(5-2 i)(x+i y)+3=i(11-i)-4 i$
11. Find the real values of $u$ and $v$ if $u=2$ $v=3$
12. If $z_{1}=4+5 i$ and $z_{2}=\alpha-2 i$, find the real values of $\alpha$ such that $\operatorname{Re}\left(z_{1} z_{2}\right)=20$.

# 1.3 Complex Polynomials as a Product of Linear Factors 

A complex polynomial $P(z)$ is a polynomial function of the complex variable $z$ with complex coefficients. It is expressed in the general form as:

$$
P(z)=a_{n} z^{n}+a_{n-1} z^{n-1}+\ldots+a_{1} z+a_{0}
$$

where $a_{n}, a_{n-1}, \ldots, a_{1}, a_{0}$ are complex numbers $\left(a_{n} \neq 0\right)$, and $n \geq 0$ is an integer representing the degree of the polynomial.
For examples $P_{1}(z)=(1-i) z+3 i, P_{2}(z)=(5-4 i) z^{2}+(2+i) z+(3-4 i)$ and $P_{3}(z)=(2-i) z^{3}+2 z^{2} i+(5+3 i)$ are the examples of linear, quadratic and cubic complex polynomials respectively. If $n=0$, then $P(z)$ becomes a constant polynomial. A fundamental property of complex polynomials is that they can always be factored into a product of linear factors.
According to the Fundamental theorem of algebra, a polynomial of degree $n \geq 1$ has exactly $n$ roots in complex number system $C$.

A corollary to this theorem states that any polynomial $P(z)$ of degree $n$ can be factored completely into a constant $a$ and $n$ linear factor over $C$ in the form

$$
P(z)=a\left(z-z_{1}\right)\left(z-z_{2}\right) \ldots\left(z-z_{n}\right)
$$

where $z_{1}, z_{2}, \ldots, z_{n}$ are complex roots of the polynomial equation $P(z)=0$. Once we know the roots of a polynomial equation $P(z)=0$ we can apply equation (1) to factored the polynomial $P(z)$ into $n$ linear factors. Specifically, if $z_{1}$ and $z_{2}$ are roots of the polynomial equation $P(z)=0$, then the equation must be $P(z)=\left(z-z_{1}\right)\left(z-z_{2}\right)$. For examples, the polynomial $P(x)=x^{2}+4$ consists of real coefficient has no real roots, so it cannot be factored into linear polynomials with real coefficients. However, if we considered the polynomial $P(z)=z^{2}+4$ as a complex polynomial, we can easily be factored into two linear factors as:

$$
z^{2}+4=(z+2 i)(z-2 i)
$$

where $2 i$ and $-2 i$ are the complex roots of $z^{2}+4=0$
fif $P(z)$ is a polynomial function, the values of $z$ that satisfy $P(z)=0$ are called the zeros of the function $P(z)$ and roots of the polynomial equation $P(z)=0$.
Example 6 Factorize the polynomial $P(z)=z^{2}+(i-3) z-3 i$.
Solution $P(z)=z^{2}+(i-3) z-3 i$

$$
\begin{aligned}
& =z^{2}+z i-3 z-3 i \\
& =z(z+i)-3(z+i) \\
& =(z+i)(z-3)
\end{aligned}
$$

Example 7 Factorize the polynomial $P(z)=z^{2}-4 i z+12$.
Solution $P(z)=z^{2}-4 i z+12$

$$
\begin{aligned}
& =z^{2}-4 i z-(-12) \\
& =z^{2}-4 i z-i^{2} 12 \quad \because \quad i^{2}=-1 \\
& =z^{2}-6 i z+2 i z-i^{2} 12 \\
& =z(z-6 i)+2 i(z-6 i) \\
& =(z-6 i)(z+2 i)
\end{aligned}
$$

Example 8 Factorize the polynomial $P(z)=z^{3}+(1+i) z^{2}+i z$.
Solution $P(z)=z^{3}+(1+i) z^{2}+i z$

$$
\begin{aligned}
& =z\left[z^{2}+(1+i) z+i\right] \\
& =z\left[z^{2}+z+i z+i\right] \\
& =z[z(z+1)+i(z+1)] \\
& =z[(z+1)(z+i)] \\
& =z(z+1)(z+i)
\end{aligned}
$$

# Key concept 

The Rational Root Theorem is a mathematical tool used to find all possible rational roots of a polynomial equation with integer coefficients. According to rational root theorem:
If a polynomial $P(x)=a_{x} x^{x}+a_{x+} x^{x^{2}}+\ldots+a_{1} x+a_{x}$ has integer coefficients, then every rational root $\frac{p}{q}$ (in the simplest terms) satisfies:
(i) $\quad p$ is a factor of the constant term $a_{i y}$ (ii) $q$ is a factor of the leading coefficient $a_{x}$.

Example 9 Factorize the polynomial $P(z)=z^{3}-3 z^{2}+z+5$.
Solution According to rational root theorem the possible root of the equation are $\pm 1$ and $\pm 5$. On checking, we see that $z=-1$ is the root of $P(z)=0$ because

$$
P(-1)=(-1)^{3}-3(-1)^{2}+(-1)+5=0
$$

So $z+1$ is a factor of the $P(z)$. Using synthetic division

$$
\begin{array}{c|ccc}
-1 & 1 & -3 & 1 & 5 \\
\hline & -1 & -1 & 4 & -5 \\
\hline 1 & -4 & 5 & 0
\end{array}
$$

Therefore, $z^{3}-3 z^{2}+z+5=(z+1)\left(z^{2}-4 z+5\right)$
Next find the factors of $z^{3}-4 z+5$ using quadratic formula

$$
\begin{aligned}
& z^{2}-4 z+5=0, \text { here } a=1, b=-4, c=5 \\
& z=\frac{-(-4) \pm \sqrt{(-4)^{2}-4(1)(5)}}{2(1)}=\frac{4 \pm \sqrt{16-20}}{2}=\frac{4 \pm \sqrt{-4}}{2}=\frac{4 \pm 2 i}{2} \\
& \Rightarrow z=2 \pm i
\end{aligned}
$$

The quadratic factors of $z^{2}-4 z+5=(z-(2+i))(z-(2-i))=(z-2-i)(z-2+i)$
Substituting in equation (i), we have the

$$
z^{3}-3 z^{2}+z+5=(z+1)(z-2-i)(z-2+i)
$$

### 1.3.1 Soiction of Quadratic Equation by Completing the Square

As we learned in previous classes, completing the square is a powerful and systematic method for solving quadratic equations. This technique involves rewriting a quadratic equation in the form $a x^{2}+b x+c=0$ into a perfect square trinomial, which can then be solved by taking the square root of both sides. This method is especially valuable when the quadratic equation does not factor easily. By completing the square, we can solve any quadratic equation, even those with irrational or complex roots, making it a more effective technique in algebra.
Example 10 Solve the equation $2 z^{2}-12 z+50=0$ by completing square method and hence express it as a product of its linear factors.

Solution $2 z^{2}-12 z+50=0$
Dividing both sides by 2

$$
\begin{aligned}
z^{2}-6 z+25 & =0 \\
\Rightarrow \quad z^{2}-2(3) z & =-25
\end{aligned}
$$

Add $3^{2}$ on both sides

$$
\begin{aligned}
z^{2}-2(3) z+3^{2} & =-25+3^{2} \\
(z-3)^{2} & =-16 \\
\Rightarrow \quad z-3 & = \pm \sqrt{-16} \\
\Rightarrow \quad z & =3 \pm 4 i
\end{aligned}
$$

Therefore, $z=3+4 i$ or $z=3-4 i$ are the required complex roots.
Using the corollary of Fundamental theorem of Algebra the equation can be factorized using the roots $3+4 i$ and $3-4 i$ as:
$2 z^{2}-12 z+50=2\left(z^{2}-6 z+25\right)=2(z-(3+4 i))(z-(3-4 i))=2(z-3-4 i)(z-3+4 i)$
Hence, $2 z^{2}-12 z+50=2(z-3-4 i)(z-3+4 i)$

# EXERCISE 1.3 

1. Factorize the following:
(i) $a^{2}+4 b^{2}$
(ii) $9 a^{2}+16 b^{2}$
(iii) $3 x^{2}+3 y^{2}$
(iv) $144 x^{2}+225 y^{2}$
(v) $z^{2}-2 i z-1$
(vi) $z^{2}+6 z+13$
(vii) $z^{2}+4 z+5$
(viii) $2 z^{2}-22 z+65$
2. Factorize the following polynomals into its linear factors:
(i) $z^{3}+8$
(ii) $z^{3}+27$
(iii) $z^{3}-2 z^{2}+16 z-32$
(iv) $z^{4}+21 z^{2}-100$
(v) $z^{4}-16$
(vi) $z^{4}+3 z^{2}-4$
(vii) $z^{4}+5 z^{2}+6$
(viii) $z^{4}-32 z^{2}-3969$
3. Find the roots of $z^{4}+7 z^{2}-144=0$ and hence express it as a product of linear factors.
4. Solve the following complex quadratic equations by completing square method:
(i) $2 z^{2}-3 z+4=0$
(ii) $z^{2}-6 z+30=0$
(iii) $3 z^{2}-18 z+50=0$
(iv) $z^{2}+4 z+13=0$
(v) $2 z^{2}+6 z+9=0$
(vi) $3 z^{2}-5 z+7=0$
5. Solve the following equations:
(i) $2 z^{4}-32=0$
(ii) $3 z^{2}-243 z=0$
(iii) $5 z^{2}-5 z=0$
(iv) $z^{3}-5 z^{2}+z-5=0$
(v) $4 z^{4}-25 z^{2}-21=0$
(vi) $z^{3}+z^{2}+z+1=0$
6. Find a polynomial $P(z)$ of degree 3 with zeros $3,-2 i, 2 i$ and satisfying $P(1)=20$.
7. Find a polynomial $P(z)$ of degree 4 with zeros $2 i,-2 i, 1,-1$, and satisfying $P(2)=240$.
8. Find a polynomial $P(z)$ of degree 4 with zeros $4,-4,1+i, 1-i$ and satisfying $P(2)=72$.

# 1.4 Three Cube Roots of Unity 

Let $x$ be a cube root of unity

$$
\begin{aligned}
& \therefore \quad x=(1)^{\frac{1}{3}} \\
& \Rightarrow \quad x^{3}=1 \\
& \Rightarrow \quad x^{3}-1=0 \\
& \Rightarrow \quad(x-1)\left(x^{2}+x+1\right)=0 \\
& \text { Either } \quad x-1=0 \Rightarrow x=1 \\
& \text { or } \quad x^{2}+x+1=0 \\
& \therefore \quad x=\frac{-1 \pm \sqrt{1-4}}{2} \\
& \Rightarrow \quad x=\frac{-1 \pm \sqrt{3} i}{2}
\end{aligned}
$$

## Note

We know that the numbers containing $i$ are called imaginary numbers. So $\frac{-1+\sqrt{3} i}{2}$ and $\frac{-1-\sqrt{3} i}{2}$ are called imaginary cube roots of unity.

Thus, the three cube roots of unity are:

$$
1, \frac{-1+\sqrt{3} i}{2} \text { and } \frac{-1-\sqrt{3} i}{2}
$$

### 1.4.1 Properties of Cube Roots of Unity

(i) Each complex cube root of unity is square of the other

$$
\text { If } \frac{-1+\sqrt{3} i}{2}=\omega \text {, then } \frac{-1-\sqrt{3} i}{2}=\omega^{2}
$$

and if $\frac{-1-\sqrt{3} i}{2}=\omega$, then $\frac{-1+\sqrt{3} i}{2}=\omega^{2}[\omega$ is read as omega]
(ii) The sum of all the three cube roots of unity is zero i.e., $1+\omega+\omega^{2}=0$
(iii) The product of all the three cube roots of unity is unity i.e., $1 \cdot \omega \cdot \omega^{2}=\omega^{2}=1$, as a consequence of which, each imaginary cube root of unity is the reciprocal of the other, that is, $\omega=\frac{1}{\omega^{2}}, \omega^{2}=\frac{1}{\omega}$.

### 1.4.2 Four Fourth Roots of Unity

Let $x$ be a fourth root of unity

$$
\begin{aligned}
& \therefore \quad x=(1)^{\frac{1}{4}} \quad \Rightarrow \quad x^{4}=1 \quad \Rightarrow \quad x^{4}-1=0 \quad \Rightarrow \quad\left(x^{2}-1\right)\left(x^{2}+1\right)=0 \\
& \Rightarrow x^{2}-1=0 \quad \Rightarrow \quad x^{2}=1 \Rightarrow x= \pm 1 \\
& \text { and } x^{2}+1=0 \Rightarrow x^{2}=-1 \Rightarrow x= \pm i \text {. }
\end{aligned}
$$

Hence four fourth roots of unity are: $1,-1, i,-i$.

# 1.4.3 Properties of four Fourth Roots of Unity 

We have found that the four fourth roots of unity are: $1,-1,+i,-i$
(i) Sum of all the four fourth roots of unity is zero

$$
\because \quad 1+(-1)+i+(-i)=0
$$

(ii) The real fourth roots of unity are additive inverses of each other. 1 and -1 are the real fourth roots of unity and $1+(-1)=0=(-1)+1$
(iii) Both the imaginary fourth roots of unity are conjugate of each other. $i$ and $-i$ are imaginary fourth roots of unity, which are obviously conjugates of each other.
(iv) Product of all the fourth roots of unity is -1 i.e., $1 \times(-1) \times i \times(-i)=-1$

Example 11 Prove that: $\left(x^{3}+y^{3}\right)=(x+y)(x+\omega y)\left(x+\omega^{2} y\right)$
Proof: R.H.S $=(x+y)(x+\omega y)\left(x+\omega^{2} y\right)$

$$
\begin{aligned}
& =(x+y)\left[x^{2}+\left(\omega+\omega^{2}\right) y x+\omega^{2} y^{2}\right] \\
& =(x+y)\left(x^{2}-x y+y^{2}\right)=x^{3}+y^{3}=\text { L.H.S. }\left\{\because \omega^{3}=1, \omega+\omega^{2}=-1\right\}
\end{aligned}
$$

Hence proved.

## EXERCISE 1.4

1. Find the three cube roots of:
(i) 8
(ii) -8
(iii) -27
(iv) 64
(v) -125
2. Find the four fourth roots of $16,81,625$. Also show that their sum is zero in each case.
3. If $1, \omega, \omega^{2}$ are the cube roots of unity, show that $1+\omega^{n}+\omega^{2 n}=3$ where $n$ is a multiple of 3 respectively.
4. Evaluate:
(i) $\left(\frac{-1+\sqrt{-3}}{2}\right)^{4}+\left(\frac{-1-\sqrt{-3}}{2}\right)^{7}$
(ii) $(-1+\sqrt{-3})^{5}+(-1-\sqrt{-3})^{5}$
5. Show that $\left(1-\omega+\omega^{2}\right)\left(1-\omega^{2}+\omega^{4}\right)\left(1-\omega^{4}+\omega^{8}\right)\left(1-\omega^{2}+\omega^{10}\right) \ldots$ to $2 n$ factors $-2^{2 n}$
6. Prove that $\left(\frac{i+\sqrt{3}}{2}\right)^{3}+\left(\frac{i-\sqrt{3}}{2}\right)^{6}=-1$.
7. Evaluate $\sum_{k=0}^{5} \omega^{2 k}$, where $\omega$ is an imaginary cube root of unity.
8. If $\omega$ is an imaginary cube roots of unity, prove that $\frac{a+b \omega^{2}+c \omega}{a \omega^{2}+b \omega+c}=\omega$
9. If $\omega$ is a cube root of unity, prove that $\frac{a \omega^{12}+b \omega^{17}+c \omega^{19}}{a \omega^{14}+b \omega^{22}+c \omega^{20}}=\omega$

# 1.4 Polar Coordinates System 

Polar coordinates are often more convenient than Cartesian coordinates in situations involving circular or rotational symmetry, or when a problem depends on distance from a fixed point and angle relative to a reference direction. Just as the Cartesian coordinate system uses an ordered pair $(x, y)$ to describe the position of a point, the polar coordinate system determines the position of a point using a directed distance $r$ from a fixed origin $O$ (called the pole) and an angle $\theta$ that the line connecting the origin to the point makes with the polar axis (typically aligned
[Image removed]
with the positive $x$-axis).

In polar coordinate system the location of a point $P$ can be described by polar coordinates in the form $(r, \theta)$, where $r$ and $\theta$ are real numbers.
[Image removed]

While $r$ is typically considered non-negative ( $r \geq 0$ ), it is also possible for $r$ to be negative $(r<0)$. The value of $r$ changes depending on its sign, and this affects the position of the point in the plane.
When $r>0$, the angle $\theta$ is the measure of any angle in standard position whose terminal side lies along the line connecting the origin to the point $P$, measured from the polar axis (positive $x$-axis).
For example, the polar coordinates $\left(5, \frac{\pi}{4}\right)$ represent a point 5 units away from pole at an angle of $\frac{\pi}{4}$ radians.
[Image removed]

When $r<0$, the angle $\theta$ is the measure of any angle in standard position whose terminal side lies along the line connecting the origin to the point $Q$, but the point $Q$ is located $|r|$ units in the opposite direction (i.e., $\theta+\pi$ ) from the polar axis (positive $x$-axis). For example, the polar coordinates $\left(-5, \frac{\pi}{4}\right)$ represents a point 5 units away from the pole, but in the direction of $\frac{\pi}{4}+\pi=\frac{5 \pi}{4}$ radians.

# Note $(-5, \pi / 4)$ and $(5,5 \pi / 4)$ represent the same point in the plane 

### 1.4.1 The Polar Form of a Complex Nurnber

Consider the adjoining diagram representing the complex number $z=x+i y$. From the diagram, we see that $x=r \cos \theta$ and $y=r \sin \theta$, where $r=|z|$ is modulus and $\theta$ is called an argument of $z$.
Hence $\quad x+i y=r \cos \theta+i r \sin \theta$
where $r=|z|=\sqrt{x^{2}+y^{2}}$ and $\theta=\tan ^{-1} \frac{y}{x}$
Equation (i) is called the polar form of the complex number $z$.
Example 12 Express the complex number $1+i \sqrt{3}$ in polar form.
Solution Step - I: Put $r \cos \theta=1$ and $r \sin \theta=\sqrt{3}$
Step - II: $r^{2}=(1)^{2}+(\sqrt{3})^{2}$

$$
\begin{aligned}
& \Rightarrow r^{2}=1+3=4 \\
& \Rightarrow r=2
\end{aligned}
$$

Step - III: $\quad \theta=\tan ^{-1} \frac{\sqrt{3}}{1}=\tan ^{-1} \sqrt{3}=60^{\circ}$

## Note

- If $x=0, y>0$ then $\theta=90^{\circ}$
- If $x=0, y<0$ then $\theta=-90^{\circ}$
- If $x=0, y=0$ then $\theta$ is undefined.
- If $y=0, x>0$ then $\theta=0^{\circ}$.
- If $y=0, x<0$ then $\theta=180^{\circ}$.

Thus $1+i \sqrt{3}=2 \cos 60^{\circ}+i 2 \sin 60^{\circ}$
Principal Argument: The principal argument $\theta$ of a complex number $z=a+b i$ is the angle between the positive real axis and the line joining $(a, b)$ to the origin in the Argand plane.

$$
\operatorname{Arg} z=\theta=\tan ^{-1}\left(\frac{b}{a}\right) \quad(a \neq 0)
$$

It is denoted by Arg. It is a single, specific value of the argument, typically chosen within a standard range: $\operatorname{Arg} z \in(-\pi, \pi]$.

# 1.3.3 Operations on Complex Numbers in Polar Form 

## Addition and Subtraction of Complex number in Polar form

Let $z_{1}=r_{1}\left(\cos \theta_{1}+i \sin \theta_{1}\right)$ and $z_{2}=r_{2}\left(\cos \theta_{2}+i \sin \theta_{2}\right)$ be two complex numbers in polar form. The addition and subtraction of these numbers can be computed simply as

$$
z_{1}+z_{2}=r_{1}\left(\cos \theta_{1}+i \sin \theta_{1}\right)+r_{2}\left(\cos \theta_{2}+i \sin \theta_{2}\right)
$$

and $z_{1}-z_{2}=r_{1}\left(\cos \theta_{1}+i \sin \theta_{1}\right)-r_{2}\left(\cos \theta_{2}+i \sin \theta_{2}\right)$

## Multiplication of Complex number in Polar form

Let $z_{1}=r_{1}\left(\cos \theta_{1}+i \sin \theta_{1}\right)$ and $z_{2}=r_{2}\left(\cos \theta_{2}+i \sin \theta_{2}\right)$ be two complex number in polar form. The product of these numbers can be derived by multiplying them directly and simplifying

$$
\begin{aligned}
& z_{1} \cdot z_{2}=r_{1}\left(\cos \theta_{1}+i \sin \theta_{1}\right) \cdot r_{2}\left(\cos \theta_{2}+i \sin \theta_{2}\right) \\
& z_{1} \cdot z_{2}=r_{1} \cdot r_{2}\left(\cos \theta_{1} \cos \theta_{2}+i \cos \theta_{1} \sin \theta_{2}+i \sin \theta_{1} \cos \theta_{2}+i^{2} \sin \theta_{1} \sin \theta_{2}\right) \\
& z_{1} \cdot z_{2}=r_{1} \cdot r_{2}\left[\left(\cos \theta_{1} \cos \theta_{2}-\sin \theta_{1} \sin \theta_{2}\right)+i\left(\cos \theta_{1} \sin \theta_{2}+\sin \theta_{1} \cos \theta_{2}\right)\right] \quad \because i^{2}=-1 \\
& z_{1} \cdot z_{2}=r_{1} \cdot r_{2}\left[\cos \left(\theta_{1}+\theta_{2}\right)+i \sin \left(\theta_{1}+\theta_{2}\right)\right] \quad \text { (Using trigonometric identities) }
\end{aligned}
$$

Thus, multiplying two complex numbers in polar form involves multiplying their moduli and summing their arguments i.e., $\arg \left(z_{1} \cdot z_{2}\right)=\arg \left(z_{1}\right)+\arg \left(z_{2}\right)$
Example13 Find the product of $5\left(\cos \frac{\pi}{6}+i \sin \frac{\pi}{6}\right)$ and $4\left(\cos \frac{3 \pi}{2}+i \sin \frac{3 \pi}{2}\right)$.
Solution Let $z_{1}=5\left(\cos \frac{\pi}{6}+i \sin \frac{\pi}{6}\right)$ and $z_{2}=4\left(\cos \frac{3 \pi}{2}+i \sin \frac{3 \pi}{2}\right)$
Here, $r_{1}=5$ and $\theta_{1}=\frac{\pi}{6}$, while $r_{2}=4$ and $\theta_{2}=\frac{3 \pi}{2}$
Substitute this value in the product formula

$$
\begin{aligned}
z_{1} \cdot z_{2} & =r_{1} \cdot r_{2}\left[\cos \left(\theta_{1}+\theta_{2}\right)+i \sin \left(\theta_{1}+\theta_{2}\right)\right] \\
& =5 \times 4\left[\cos \left(\frac{\pi}{6}+\frac{3 \pi}{2}\right)+i \sin \left(\frac{\pi}{6}+\frac{3 \pi}{2}\right)\right]=20\left(\cos \frac{5 \pi}{3}+i \sin \frac{5 \pi}{3}\right)
\end{aligned}
$$

Thus, the required product is $20\left(\cos \frac{5 \pi}{3}+i \sin \frac{5 \pi}{3}\right)$

# Division of Complex Number in Polar Form 

Let $z_{1}=r_{1}\left(\cos \theta_{1}+i \sin \theta_{1}\right)$ and $z_{2}=r_{2}\left(\cos \theta_{2}+i \sin \theta_{2}\right)$ be two complex numbers in polar form. The formula for division of these numbers in polar form can be derived as below:
$\frac{z_{1}}{z_{2}}=\frac{r_{1}\left(\cos \theta_{1}+i \sin \theta_{1}\right)}{r_{2}\left(\cos \theta_{2}+i \sin \theta_{2}\right)}$
$\frac{z_{1}}{z_{2}}=\frac{r_{1}\left(\cos \theta_{1}+i \sin \theta_{1}\right)}{r_{2}\left(\cos \theta_{2}+i \sin \theta_{2}\right) \cdot\left(\cos \theta_{2}-i \sin \theta_{2}\right) \quad$ (Multiply and divide the R.H.S by conjugate of $\cos \theta_{2}+i \sin \theta_{2}$ )
$\frac{z_{1}}{z_{2}}=\frac{r_{1}}{r_{2}} \frac{\left(\cos \theta_{1} \cos \theta_{2}+\sin \theta_{1} \sin \theta_{2}\right)+i\left(\sin \theta_{1} \cos \theta_{2}-\cos \theta_{1} \sin \theta_{2}\right)}{\cos ^{2} \theta_{2}+\sin ^{2} \theta_{2}}$
$\frac{z_{1}}{z_{2}}=\frac{r_{1}}{r_{2}}\left[\cos \left(\theta_{1}-\theta_{2}\right)+i \sin \left(\theta_{1}-\theta_{2}\right)\right] \quad$ (Using trigonometric identities)
Thus, the modulus of the division of two complex numbers equals the quotient of their moduli, while the arguments of the quotient is the difference between their arguments.
Thus, when dividing two complex numbers, the modulus of the result is the ratio of their moduli, and the argument of the result is the difference between their arguments i.e., $\arg \left(\frac{z_{1}}{z_{2}}\right)=\arg \left(z_{1}\right)-\arg \left(z_{2}\right)$

Example 14 Divide $\frac{2}{7}\left(\cos \frac{7 \pi}{6}+i \sin \frac{7 \pi}{6}\right)$ by $\frac{3}{5}\left(\cos \left(-\frac{\pi}{2}\right)+i \sin \left(-\frac{\pi}{2}\right)\right)$.
Solution Let $z_{1}=\frac{2}{7}\left(\cos \frac{7 \pi}{6}+i \sin \frac{7 \pi}{6}\right)$ and $z_{2}=\frac{3}{5}\left(\cos \left(-\frac{\pi}{2}\right)+i \sin \left(-\frac{\pi}{2}\right)\right)$
Here, $\quad r_{1}=\frac{2}{7}, \theta_{1}=\frac{7 \pi}{6}, r_{1}=\frac{3}{5}$ and $\theta_{2}=-\frac{\pi}{2}$.
Substitute value in the quotient formula

$$
\begin{aligned}
\frac{z_{1}}{z_{2}} & =\frac{r_{1}}{r_{2}}\left[\cos \left(\theta_{1}-\theta_{2}\right)+i \sin \left(\theta_{1}-\theta_{2}\right)\right] \\
& =\frac{2}{7} \times \frac{5}{3}\left[\cos \left(\frac{7 \pi}{6}-\left(-\frac{\pi}{2}\right)\right)+i \sin \left(\frac{7 \pi}{6}-\left(-\frac{\pi}{2}\right)\right)\right] \\
\frac{z_{1}}{z_{2}} & =\frac{10}{21}\left(\cos \frac{5 \pi}{3}+i \sin \frac{5 \pi}{3}\right)
\end{aligned}
$$

Example 15 If $z=x+i y$, then write the equation $|3 z-i|=|3 z+7|$ in terms of $x$ and $y$.
Solution Given $|3 z-i|=|3 \bar{z}+7|$
$|3 z-i|=|3(x+i y)-i|=|3 x+i(3 y-1)|=\sqrt{(3 x)^{2}+(3 y-1)^{2}}$
$|3 \bar{z}+7|=|3 x+3 i y+7|=|3 x-3 i y+7|=|3 x+7+i(-3 y)|=\sqrt{(3 x+7)^{2}+(-3 y)^{2}}$
Substitutes these values in (i)

$$
\sqrt{(3 x)^{2}+(3 y-1)^{2}}=\sqrt{(3 x+7)^{2}+(-3 y)^{2}}
$$

Taking square on both sides

$$
\begin{aligned}
(3 x)^{2}+(3 y-1)^{2} & =(3 x+7)^{2}+(-3 y)^{2} \\
9 x^{2}+9 y^{2}-6 y+1 & =9 x^{2}+42 x+49+9 y^{2} \\
\Rightarrow \quad-6 y+1 & =42 x+49 \\
\Rightarrow \quad-6 y & =42 x+48 \\
\text { or } \quad y & =-7 x-8
\end{aligned}
$$

The equation $y=-7 x-8$ represents a straight line in the complex plane.
Example 16 Show that $(x+2)^{2}+y^{2}=8$ if $\arg \left(\frac{z+2 i}{z-2 i}\right)=\frac{3 \pi}{4}$ for $z=x+i y$.
Solution $\frac{z+2 i}{z-2 i}=\frac{x+i y+2 i}{x+i y-2 i}=\frac{x+i(y+2)}{x+i(y-2)}=\frac{x+i(y+2)}{x+i(y-2)} x \frac{x-i(y-2)}{x-i(y-2)}$
$\Rightarrow \quad \frac{z+2 i}{z-2 i}=\frac{\left(x^{2}+y^{2}-4\right)+4 i x}{x^{2}+(y-2)^{2}}=\frac{x^{2}+y^{2}-4}{x^{2}+(y-2)^{2}}+i \frac{4 x}{x^{2}+(y-2)^{2}}$
As

$$
\arg \left(\frac{z+2 i}{z-2 i}\right)=\frac{3 \pi}{4}
$$

$\Rightarrow \quad \tan ^{-1}\left(\frac{4 x}{\frac{x^{2}+(y-2)^{2}}{x^{2}+y^{2}-4}}\right)=\frac{3 \pi}{4} \quad \Rightarrow \quad \frac{4 x}{x^{2}+y^{2}-4}=\tan \frac{3 \pi}{4}=-1$
$\Rightarrow \quad 4 x=-1\left(x^{2}+y^{2}-4\right) \quad \Rightarrow \quad x^{2}+4 x+y^{2}=4$
Completing the square for $x^{2}$, we have

$$
(x+2)^{2}+y^{2}=8
$$

# 1.5 Complex Numbers in the Real World (Voltage, Current and Resistance) 

Ohm's Law is a fundamental principle in physics that describes the relationship between voltage $V$, current $I$ and resistance $R$ in an electrical circuit. Mathematically Ohm's Law can be expressed by the formula $V=I R$.
When dealing with alternating current (AC) circuits, resistance generalizes to impedance ( $Z$ ). Resistance in a circuit is due to inductor $\left(X_{L}\right)$ and capacitor $\left(X_{C}\right)$. Their difference is reactance $X=\left(X_{L}\right)-\left(X_{C}\right)$. Geometrically it is shown in the adjacent figure. Here $Z=R+i X$.
Then for AC circuits, Ohm's Law in Terms of Impedance is expressed by the formula $V=I \cdot Z$.
[Image removed]

Example 17 If the impedance of circuit is $11\left(\cos 55.35^{\circ}+i \sin 55.35^{\circ}\right)$ ohms at a voltage of $25\left(\cos 30^{\circ}+i \sin 30^{\circ}\right) V$, find the value of current in the circuit.
Solution Substitute the voltage $25\left(\cos 30^{\circ}+i \sin 30^{\circ}\right)$ and impedance $11\left(\cos 55.35^{\circ}+i \sin 55.35^{\circ}\right)$ into the equation $V=I Z$, where $V$ is voltage, $I$ denote the current and $Z$ is impedance.

$$
\begin{aligned}
25\left(\cos 30^{\circ}+i \sin 30^{\circ}\right) & =I .11\left(\cos 55.35^{\circ}+i \sin 55.35^{\circ}\right) \\
\text { or } \quad I & =\frac{25\left(\cos 30^{\circ}+i \sin 30^{\circ}\right)}{11\left(\cos 55.35^{\circ}+i \sin 55.35^{\circ}\right)} \\
I & =\frac{25}{11}\left[\cos \left(30^{\circ}-55.35^{\circ}\right)+i \sin \left(30^{\circ}-55.35^{\circ}\right)\right. \\
I & =2.27\left[\cos \left(-25.35^{\circ}\right)+i \sin \left(-25.35^{\circ}\right)\right.
\end{aligned}
$$

Express into rectangular form

$$
I=2.27[0.90+i(-0.42)]=2.04-0.95 i
$$

Thus, current is $2.04-0.95 i A$.
Cryptography: It is the science of securing information by transforming readable messages called plaintext into secret code called ciphertext using mathematical algorithms and encryption keys. It consists of two main processes i.e., encryption to lock message with complex math, and decryption to unlock it with the right key.
Example 18 Encrypt the word "MATH" by multiplying it with a complex number $k=2+3 i$ and then decrypted back to its original form using the concept of multiplicative inverse in complex numbers.
Each letter of the alphabet is assigned a numerical value as follows:

$$
A=1, B=2, C=3, \ldots, Z=26
$$

# Unit 4 Complex Numbers 

Solution First, we assign each letter in the word "MATH" a complex number with zero imaginary part. The encryption and decryption are shown in the table below

| Letter | Complex Number (x) | $z$ encrypted $-z \times k$ | $z$ decrypled $-z$ encrypted $/ k$ | Letter |
| :--: | :--: | :--: | :--: | :--: |
| M | $13+0 i$ | $(13+0 i)(2+3 i)=26+39 i$ | $(26+39 i) /(2+3 i)=13+0 i$ | M |
| A | $1+0 i$ | $(1+0 i)(2+3 i)=2+3 i$ | $(2+3 i) /(2+3 i)=1+0 i$ | A |
| T | $20+0 i$ | $(20+0 i)(2+3 i)=40+60 i$ | $(40+60 i) / 2+3 i=20+0 i$ | T |
| H | $8+0 i$ | $(8+0 i)(2+3 i)=16+24 i$ | $16+24 i / 2+3 i=8+0 i$ | H |

## EXERCISE 1.5

1. Plot the following points:
(i) $(2,75)$
(ii) $(-3,120)$
(iii) $\left(2, \frac{\pi}{6}\right)$
(iv) $\left(5, \frac{5 \pi}{6}\right)$
(v) $\left(-\frac{5}{2}, \frac{\pi}{3}\right)$
(vi) $\left(-3,-\frac{2 \pi}{3}\right)$
(vii) $\left(-\frac{9}{2},-\frac{19 \pi}{12}\right)$
(viii) $\left(-\frac{5}{2}, \frac{5 \pi}{12}\right)$
2. Express the following complex numbers in polar form:
(i) $4+3 i$
(ii) $1+i$
(iii) $\frac{1}{2}+\frac{\sqrt{3}}{2} i$
(iv) $-\frac{5}{2}-\frac{5 \sqrt{3}}{2} i$
(v) $\frac{1-i}{1+i}$
(vi) $\frac{\sqrt{3}+i}{1+\sqrt{3} i}$
(vii) $\frac{3+4 i}{4+3 i}$
3. Convert each of the complex number $z$ in the rectangular form $x+i y$ :
(i) $4\left(\cos \frac{5 \pi}{3}+i \sin \frac{5 \pi}{3}\right)$
(ii) $\frac{3}{2}\left(\cos \frac{7 \pi}{6}+i \sin \frac{7 \pi}{6}\right)$
(iii) $|z|=7, \arg (z)=\frac{23 \pi}{12}$
(iv) $|z|=11, \arg (z)=-\frac{11 \pi}{12}$
(v) $|z|=\frac{10}{3}, \arg (z)=-\frac{17 \pi}{12}$
(vi) $2 \cos (-33)+i 2 \sin (-33)$
4. If $z_{1}=9\left(\cos \frac{5 \pi}{4}+i \sin \frac{5 \pi}{4}\right)$ and $z_{2}=5\left(\cos \frac{\pi}{3}+i \sin \frac{\pi}{3}\right)$ then find
(i) $z_{1}+z_{2}$
(ii) $z_{1}-z_{2}$
(iii) $z_{1} \cdot z_{2}$
(iv) $\frac{z_{1}}{z_{2}}$
5. If $z_{1}=7\left(\cos \frac{23 \pi}{12}+i \sin \frac{23 \pi}{12}\right)$ and $z_{2}=11\left(\cos \frac{11 \pi}{12}+i \sin \frac{11 \pi}{12}\right)$ then find the following and express the result into $x+i y$ form
(i) $z_{1}+z_{2}$
(ii) $z_{1}-z_{2}$
(iii) $z_{1} \cdot z_{2}$
(iv) $\frac{z_{1}}{z_{2}}$

6. If $z_{1}$ and $z_{2}$ are two complex numbers, show that
(i) $\operatorname{Arg}\left(z_{1} z_{2}\right)=\operatorname{Arg} z_{1}+\operatorname{Arg} z_{2}$
(ii) $\operatorname{Arg}\left(\frac{z_{1}}{z_{2}}\right)=\operatorname{Arg} z_{1}-\operatorname{Arg} z_{2}$
7. Divide $z_{1}=6\left(\cos 150^{\circ}+i \sin 150^{\circ}\right)$ by $z_{2}=3\left(\cos 30^{\circ}+i \sin 30^{\circ}\right)$ and express in $x+i y$ form.
8. Multiply $z_{1}=2\left(\cos 60^{\circ}+i \sin 60^{\circ}\right)$ and $z_{2}=5\left(\cos 90^{\circ}+i \sin 90^{\circ}\right)$ and express in $x+i y$ form.
9. Find the modulus and argument of $z=-2-2 i$.
10. Write the equation $\arg (\bar{z}-2+i)=\frac{2 \pi}{3}$ in cartesian form, if $z=x+i y$.
11. If $z=x+i y$ and $\arg \left(\frac{\bar{z}-1+2 i}{\bar{z}+1-2 i}\right)=\frac{9 \pi}{4}$, show that $x^{2}+y^{2}+4 x+2 y-5=0$.
12. If $z=x+i y$ and $\arg (z-2-3 i)-\arg (z+2+3 i)=2 \pi$, show that $2 y=3 x$.
13. Solve the equation $|z-2 i|=|\bar{z}+2|$ for $z=x+i y$.
14. For $z=x+i y$, solve the equation $\left|5 z+4+i\right|=5 \bar{z}-3+2 i$.
15. Determine the set of points $z=x+i y$ that satisfy the equation $3 \bar{z}-2+i|=3 z+i|$.
16. If $z=x+i y$ and $w=\frac{1-i z}{z-z}$ show that $|w|=1 \Rightarrow z$ is real.
17. If $z_{1}$ and $z_{2}$ are different complex numbers with $\left|z_{2}\right|=1$, find $\left|\frac{z_{2}-z_{1}}{1-z_{1} z_{2}}\right|$.
18. An AC source supplies a voltage of $V=120\left(\cos \frac{\pi}{4}+i \sin \frac{\pi}{4}\right)$ volts to a circuit with impedance $Z=\frac{1+i \sqrt{3}}{2}$ ohms. Calculate the current in polar form.
19. An AC circuit has an impedance of $Z=3-6 i$ ohms and is connected to a voltage source of $V=90+30 i$ volts. Find the current in both rectangular and polar form.
20. Encrypt the word "CODE" by multiplying the complex encryption key $k=2-i$. Then decrypt it back to the original word.
21. Consider the complex encryption key $k=3-3 i$. Encrypt the word "QUIZ", and then recover the original word using the inverse of the key.
22. Encrypt the word "CLASS" by adding the complex encryption key $k=-3+4 i$. Then decrypt it back to the original word.



# Functions and Graphs

## INTRODUCTION

Functions are of fundamental importance in mathematics, describing relationships between inputs and outputs through a rule of correspondence. Understanding key concepts such as domain, co-domain and range is essential for analyzing different types of functions, including one-to-one, onto and bijective functions. Graphical representation helps in identifying intersecting points, such as where a linear function meets the coordinate axes, where two linear functions intersect or where a linear and a quadratic function cross. These intersections provide valuable insights into solving equations visually. Additionally, exploring square root and cube root function graphs allows for a deeper understanding of their unique properties and behaviour. This unit will enhance problem-solving skills by combining algebraic and graphical approaches to functions.

### 2.1 Concept of Function

The term function was recognized by a German Mathematician Leibniz (1646-1716) to describe the dependence of one quantity on another. The following examples illustrate how this term is used:
(i) The area $A$ of a square depends on one of its sides $x$ by the formula $A=x^{2}$, so we say that $A$ is a function of $x$.
(ii) The volume " $V$ " of a sphere depends on its radius $r$ by the formula $V=\frac{4}{3} \pi r^{3}$, so we say that $V$ is a function of $r$.
A function is a rule of correspondence, relating two sets in such a way that each element in the first set corresponds to one and only one element in the second set.
Thus in, (i) above, a square of a given side has only one area and in, (ii) above, a sphere of a given radius has only one volume.
Now we have a formal definition:

### 2.1.1 Definition (Function, Domain, Codomain, Range)

A function $f$ from a set $X$ to a set $Y$ is a rule of a correspondence that assigns to each element $x$ in $X$ a unique element $y$ in $Y$. The set $X$ is called the domain of $f$.
The set of corresponding elements $y$ in $Y$ is called the range of $f$. While the codomain of a function is the set $Y$ in which function's output values (range) lie.
Unless stated to the contrary, we shall assume hereafter that the set $X$ and $Y$ consist of real numbers.

Note Co-domain is the set of all possible outputs but the range is the actual set of outputs produced by the function under the given domain that is range set is always a subset of co-domain.

# 2.1.2 Notation and Value of a Function 

If a variable $y$ depends on a variable $x$ in such a way that each value of $x$ determines exactly one value of $y$, then we say that " $y$ is a function of $x$ ".
Swiss mathematician Euler (1707 - 1783) invented a symbolic way to write the statement " $y$ is a function of $x$ " as $y=f(x)$, which is read as " $y$ is equal to $f$ of $x$ ".
A function can be thought as a computing machine $f$ that takes an input $x$, operates on it in some way and produces exactly one output $f(x)$. This output $f(x)$ is called the value of $f$ at $x$ or image of $x$ under $f$.
[Image removed]

The output $f(x)$ is denoted by a single letter, say $y$ and we write $y=f(x)$.
The variable $x$ is called the independent variable of $f$ and the variable $y$ is called the dependent variable of $f$. For now onward we shall only consider the function in which the variables are real numbers and we say that $f$ is a real valued function of real numbers.
Example 1 Given $f(x)=x^{3}-2 x^{2}+4 x-1$, find:
(i) $f(0)$
(ii) $f(1)$
(iii) $f(-2)$
(iv) $f(1+x)$
(v) $f\left(\frac{1}{x}\right), x \neq 0$

Solution $f(x)=x^{3}-2 x^{2}+4 x-1$
(i) $f(0)=0-0+0-1=-1$
(ii) $f(1)=(1)^{3}-2(1)^{2}+4(1)-1=1-2+4-1=2$
(iii) $f(-2)=(-2)^{3}-2(-2)^{2}+4(-2)-1=-8-8-8-1=-25$
(iv) $f(1+x)=(1+x)^{3}-2(1+x)^{2}+4(1+x)-1$

$$
\begin{aligned}
& =1+3 x+3 x^{2}+x^{3}-2-4 x-2 x^{2}+4+4 x-1 \\
& =x^{3}+x^{2}+3 x+2
\end{aligned}
$$

(v) $f\left(\frac{1}{x}\right)=\left(\frac{1}{x}\right)^{3}-2\left(\frac{1}{x}\right)^{2}+4\left(\frac{1}{x}\right)-1=\frac{1}{x^{2}}-\frac{2}{x^{2}}+\frac{4}{x}-1, x \neq 0$

Example 2 Find the domain and range of $f(x)=x^{2}$.
Solution For every real number $x, f(x)=x^{2}$ is a non-negative real number. So, Domain $f=$ set of all real numbers ; Range $f=$ set of all non-negative real numbers.

Example 3 Find the domain and range of $f(x)=\frac{x}{x^{2}-4}$.
Solution At $x=2$ and $x=-2, f(x)=\frac{x}{x^{2}-4}$ is not defined. So,
Domain $f=$ set of all real numbers except -2 and 2 or $R-\{-2,2\}$
Let $y=\frac{x}{x^{2}-4} \Rightarrow y\left(x^{2}-4\right)=x \Rightarrow x^{2} y-4 y=x$

$$
\begin{aligned}
x^{2} y-x-4 y & =0 \\
x & =\frac{-(-1) \pm \sqrt{(-1)^{2}-4(y)(-4 y)}}{2 y} \\
x & =\frac{1 \pm \sqrt{1+16 y^{2}}}{2 y}, y \neq 0
\end{aligned}
$$

## Remember

There are two types of intervals known as open interval and closed interval. In an open interval $(a, b)$, the endpoints are not included. In a closed interval $[a, b]$, the endpoints are included.

Clearly $x$ is defined for all $y \neq 0$

$$
\text { For } y=0 \text {, we have } 0=\frac{x}{x^{2}-4} \Rightarrow x=0
$$

This is $f(0)=0$
So, range $f=$ set of all real numbers or $(-\infty, \infty)$
Example 4 Find the domain and range of $f(x)=\sqrt{x^{2}-9}$.
Solution As square root of a negative number is not a real number, therefore $x^{2}-9 \geq 0$
(i)

Let $x^{2}-9=0 \Rightarrow x= \pm 3$
Critical points divide the number line into three regions:
Put $x=-4$ in (i), $16-9 \geq 0$ (True)
Put $x=0$ in (i), $0-9 \geq 0$ (False)
Put $x=4$ in (i), $16-9 \geq 0$ (True)
So, domain $f \doteq(-\infty,-3] \cup[3, \infty)$
The smallest value of $x^{2}-9$ is 0 (when $x= \pm 3$ ).
$\Rightarrow y=\sqrt{x^{2}-9}=\sqrt{0}=0$
As $|x|$ increases beyond $3, x^{2}-9$ grows to $+\infty$, so $y$ grows to $+\infty$.
So, range $f=[0, \infty)$

# 2.1.3 Vertical Line Test 

The vertical line test is a method used to determine whether a graph represents a function. A graph represents a function if and only if no vertical line intersects the graph more than once. If any vertical line passes through the graph more than once, it is not a function.

Explanation is given in the following figure.
[Image removed]

# 2.1.4 Types of Function 

## (i) One-to-One (Injective) Function

A function $f: x \rightarrow y$ is one-to-one if different inputs produce different outputs, that is if $f\left(x_{1}\right)=f\left(x_{2}\right)$ implies $x_{1}=x_{2}$. This means that no two different elements of the domain map to the same element of the co-domain.
For example, $f(x)=5 x+7$ is one-to-one because if $5 x_{1}+7=5 x_{2}+7$ implies $x_{1}=x_{2}$.

## (ii) Onto (Surjective) Function

A function $f: X \rightarrow Y$ is called onto (or surjective) function if every element in the co-domain $Y$ has at least one pre-image in the domain $X$. In other words, for every $y$ in $Y$, there exists an $x$ in $X$ such that $f(x)=y$.
For example, $f(x)=2 x+3$, where the domain and co-domain are both real numbers.
Here $y=2 x+3 \Rightarrow x=\frac{y-3}{2}$. Here for each $y$ in $R$, there exists $\frac{y-3}{2}$ in $R$ such that $f\left(\frac{y-3}{2}\right)=y$. Hence $f$ is an onto function.

## (iii) Bijective Function

A function $f: X \rightarrow Y$ is called bijective if it is both one-to-one and onto.
Piecewise Function
A piecewise function is a function that is defined by different expressions (or "pieces") over different intervals of its domain. Each piece applies to a specific part of the domain.
For example, $\quad f(x)=\left\{\begin{array}{l}2 x+1 \text { if } x<0 \\ x^{2}-1 \text { if } x \geq 0\end{array}\right.$
For $x<0$, the function behaves as $2 x+1$ and for $x \geq 0$, it behaves as $x^{2}-1$
[Image removed]

Example 5 Show that the function $f(x)=x+1$, where the domain and co-domain are all real numbers, is bijective.
Solution A function is bijective if it is both one-to-one and onto.
A function is one-to-one if $f\left(x_{1}\right)=f\left(x_{2}\right) \Rightarrow x_{1}=x_{2}$ for $f(x)=x+1$
Suppose $f\left(x_{1}\right)=f\left(x_{2}\right)$

$$
\begin{aligned}
& \Rightarrow \quad x_{1}+1=x_{2}+1 \\
& \Rightarrow \quad x_{1}=x_{2}
\end{aligned}
$$

So, the given function is one-to-one.
It is also onto because for every real number $y$, there is a real number $x$ (specifically $x=y-1$ ) such that $f(y-1)=y-1+1=y$. Hence, $f(x)$ is bijective.
Exemple 6 Show that the function $f(x)=x^{2}-2$, where the domain and co-domain are all real numbers, is neither one-to-one nor onto.
Solution As $f\left(x_{1}\right)=f\left(x_{2}\right) \Rightarrow x_{1}^{2}-2=x_{2}^{2}-2 \Rightarrow x_{1}^{2}=x_{2}^{2}$
Taking square root, we get $x_{1}=x_{2}$ or $x_{1}=-x_{2}$
This does not imply that $x_{1}=x_{2}$, for example $x_{1}=2, x_{2}=-2 \Rightarrow x_{1} \neq x_{2}$ and $f(2)=2=f(-2)$.
Thus, $f$ is not one-to-one.
Also, the element -2 in the co-domain $R$ is the smallest value that $f(x)=x^{2}-2$ can attain, and it is only achieved when $x=0$. However, any number less than -2 (in co-domain $R$ ) is not the image of any real number $x$ in domain $R$. For example, $f(x)=-3 \Rightarrow x^{2}-2=-3$ has no
[Image removed]
real root. Hence, $f(x)$ is nether one-to-one nor onto.

# EXERCISE 2.1 

1. Given that:
(a) $f(x)=x^{2}-1$
(b) $f(x)=\sqrt{2 x+3}$
Find:
(i) $f(-3)$
(ii) $f(0)$
(iii) $f(x-2)$
(iv) $f\left(x^{2}+3\right)$
2. Find $\frac{f(a+h)-f(a)}{h}$ and simplify where,
(i) $f(x)=4 x+7$
(ii) $f(x)=\sin x$
(iii) $f(x)=x^{3}+x^{2}-1$
(iv) $f(x)=\tan x$

3. Express the following:
(a) The area $A$ of a square as a function of its perimeter $P$.
(b) The circumference $C$ of a circle as a function of its area $A$.
(c) The surface area $S$ of a cube as a function of its volume $V$.
4. Find the domain and the range of the function $g$ defined below:
(i) $g(x)=5-x$
(ii) $g(x)=\sqrt{x+2}$
(iii) $g(x)= \begin{cases}6 x+7, & x \leq-2 \\ 4-3 x, & x>-2\end{cases}$
(iv) $g(x)=|x-5|$
(v) $g(x)=\frac{x+2}{3-x}$
5. Given $f(x)=x^{3}-a x^{2}+b x+1$. If $f(2)=-3$ and $f(-1)=0$. Find the values of $a$ and $b$.
6. A stone falls from a height of 60 m on the ground, the height $h$ after $x$ seconds is approximately given by $h(x)=40-10 x^{2}$.
(i) What is the height of stone when:
(a) $x=1 \mathrm{sec}$ ?
(b) $x=1.5 \mathrm{sec}$ ?
(c) $x=1.7 \mathrm{sec}$ ?
(ii) When does the stone strike the ground?
7. Consider the function $f(x)=3 x-5$.
(i) Determine the domain and range of $f(x)$.
(ii) Is the function $f$ one-to-one? Justify your answer.
(iii) Is the function $f$ onto if the co-domain is all real numbers? Explain.
8. Let $f: R \rightarrow R$ be defined by $f(x)=\frac{2 x-3}{x+1}$.
(i) Find the domain and range of $f(x)$. (ii) Determine whether $f(x)$ is onto.
(iii) Prove that $f(x)$ is one-to-one.
9. Consider the function $f: \mathrm{R}^{+} \rightarrow \mathrm{R}^{+}$defined by $f(x)=e^{-x}$. Show that $f(x)$ is a bijective.
10. Let $g: R \rightarrow R$ be given by $g(x)=x^{3}-3 x$. Determine if $g(x)$ is injective and/or surjective.

# 2.2 Finding the Intersecting Point(s) Graphically 

The point of intersection is a point where two or more graphs meet on the coordinate plane. This point represents the solution to the equation of the given function.

### 2.2.1 Intersection of a Linear Function and Coordinate Axes

As we know that linear function is a function in which the highest power of the variable is one. While the coordinate axes refers to $x$-axis and $y$-axis in the Cartesian coordinate system.

Example 7 Find the points of intersection of a linear function $y=2 x+6$ and coordinate axes graphically.
Solution Table of values of $y=2 x+6$ are given below:

| $x$ | $y=2 x+6$ |
| :--: | :--: |
| -1 | 4 |
| 0 | 6 |
| 1 | 8 |

[Image removed]

Hence, from the above graph, the points $(-3,0)$ and $(0,6)$ are the points of intersection of $y=2 x+6$ and coordinate axes.

# 2.2.2 Intersection of Two Linear Functions 

The point of intersection of two linear functions is the point where their graphs cross each other. This means the two functions have the same $x$ and $y$ values at that point.
Example 8 Find the point of intersection of $y=3 x+2$ and $y=-x+6$ graphically.
Solution Table of different values of $x$ and $y$ is given below:

| $x$ | $y=3 x+2$ | $y=-x+6$ |
| :--: | :--: | :--: |
| -1 | -1 | 7 |
| 0 | 2 | 6 |
| 1 | 5 | 5 |

By plotting the above points, we see that $(1,5)$ is the point of intersection of both the straight lines as shown in figure.
[Image removed]

### 2.2.3 Intersection of a Linear Function and a Quadratic Function

A line and a parabola can either intersect at two points, one point or not as intersect at all. If there are two solutions, the system has two points of intersection. A single solution indicates that there is only one intersection point, suggesting that the line may be tangent to the parabola. If no solution exists, it means the line and the

parabola do not intersect.
[Image removed]

Example 9 Solve the linear function $y=-x+3$ and quadratic function $y=x^{2}-6 x+3$ graphically.
Solution Clearly $(3,0)$ and $(0,3)$ are the $x$-intercept and $y$-intercept respectively of $y=-x+3$.

$$
y=x^{2}-6 x+3
$$

Put $x=0$ in (i), so $(0,3)$ is the $y$-intercept.
Put $y=0$ in (i), we have

$$
\begin{aligned}
0 & =x^{2}-6 x+3 \\
x & =\frac{-(-6) \pm \sqrt{(-6)^{2}-4(1)(3)}}{2(1)} \\
& =\frac{6 \pm \sqrt{36-12}}{2}=\frac{6 \pm \sqrt{24}}{2} \\
& =\frac{6 \pm 2 \sqrt{6}}{2}=3 \pm \sqrt{6} \\
& =3-\sqrt{6}, 3+\sqrt{6}=0.6,5.4
\end{aligned}
$$

So $(0.6,0)$ and $(5.4,0)$ are the $x$-intercepts.
Now we find vertex $(h, k)$ of the parabola

$$
\begin{aligned}
& h=-\frac{b}{2 a}=-\frac{-6}{2(1)}=3 \\
& k=(3)^{2}-6(3)+3=-6
\end{aligned}
$$

[Image removed]

So, the vertex is $(3,-6)$.
Hence $(0,3)$ and $(5,-2)$ are the solutions (points of intersection) of the given functions.

# 2.3 Graph of the Square Root Function 

Example 10 Graph the square root function $y=2 \sqrt{x}+1$
Solution Clearly the domain of $y=2 \sqrt{x}+1$ is $x \geq 0$, as the square root of a negative number is not a real number. The range of $y=2 \sqrt{x}+1$ is $y \geq 1$,
Table of values and the graph of the function are given below:

| $\boldsymbol{x}$ | $\boldsymbol{y}=\mathbf{2} \sqrt{\boldsymbol{x}}+\mathbf{1}$ |
| :--: | :--: |
| 0 | 1 |
| 1 | 3 |
| 2 | 3.8 |
| 3 | 4.5 |
| 4 | 5 |
| 5 | 5.5 |
| 6 | 5.9 |
| 7 | 6.3 |
| 8 | 6.7 |
| 9 | 7 |
| 10 | 7.3 |

[Image removed]

### 2.4 Graph of the Cube Root Function

Example 11 Graph the cube root function $y=\sqrt[3]{x-1}$
Solution Table of values and the graph of the function are given below:

| $\boldsymbol{x}$ | $\boldsymbol{y}=\sqrt[3]{\boldsymbol{x}-1}$ |
| :--: | :--: |
| -5 | $-1.8$ |
| -4 | $-1.7$ |
| -3 | $-1.6$ |
| -2 | $-1.4$ |
| -1 | $-1.3$ |
| 0 | -1 |
| 1 | 0 |
| 2 | 1 |
| 3 | 1.3 |
| 4 | 1.4 |
| 5 | 1.6 |

[Image removed]

# 2.5 Real Life Applications 

## Growth and Decay in Finance (Predicting Long-Term Stock Prices)

When something increases in quantity or size over time, it is called growth. For example, money in a bank account earning interest (it grows larger), a population of rabbits is increasing over months.
When something decreases in quantity or size over time, it is called decay. For example, a radioactive substance is losing its strength over years, a cup of hot coffee is cooling down over time.
Example 12 The value of a stock follows the exponential growth model $P(t)=P_{0} e^{r t}$, where $P_{0}$ is the initial stock price, $r$ is the growth rate per year and $t$ is the time in years. Suppose a stock is currently valued at Rs. 5,000 , and it is expected to grow at a rate of $5 \%$ per year.
(i) Find the value of the stock after 10 years.
(ii) After how many years will the stock double in value?

Solution (i) The formula for the exponential growth is:

$$
P(t)=P_{0} e^{r t}
$$

Given $\quad P_{0}=5000, r=0.05(5 \%$ growth rate), and $t=10$ years.

$$
P(10)=5000 e^{0.05 \times 10}=5000 e^{0.5}
$$

Using $e^{0.5} \approx 1.6487$

$$
P(10)=5000 \times 1.6487=8244
$$

So, the value of the stock after 10 years is approximately Rs. 8244
(ii) We want to find $t$ when the stock doubles, i.e., when $P(t)=2 P_{0}$. Using the equation:

$$
2 P_{0}=P_{0} e^{r t}
$$

Dividing both sides by $P_{0}$, we have $2=e^{r t}$
Taking the natural logarithm on both sides: $\ln 2=r t$

$$
\text { and } \quad t=\frac{\ln 2}{r}
$$

$$
\begin{aligned}
& =\frac{0.6931}{0.05} \\
& =13.86
\end{aligned}
$$

So, the stock will double in value i.e., approximately 14 years.

Example 13 The concentration of a pollutant in a lake, in parts per million (ppm), decays over time according to the function

$$
C(t)=\frac{100}{\sqrt{t+1}}
$$

where $t$ is the time in days since the pollutant was introduced.
(i) What is the concentration of the pollutant after 4 days?
(ii) After how many days will the concentration drop below 10 ppm ?

Solution (i) The pollutant concentration function is $C(t)=\frac{100}{\sqrt{t+1}}$, where $t$ is the time in days.
Concentration after 4 days:

$$
\begin{aligned}
C(4) & =\frac{100}{\sqrt{4+1}} \\
& =\frac{100}{\sqrt{5}} \\
& \approx 44.72 \mathrm{ppm}
\end{aligned}
$$

The concentration after 4 days is about 44.72 ppm .
(ii) When will the concentration drop below 10 ppm ? Set $C(t)=10$ :

$$
\begin{aligned}
& 10=\frac{100}{\sqrt{t+1}} \\
& \Rightarrow \sqrt{t+1}=10 \\
& \Rightarrow \quad t+1=100 \\
& \Rightarrow \quad t=99
\end{aligned}
$$

After 99 days, the concentration will drop below 10 ppm .

# EXERCISE 2.2 

1. Find the point of intersection of the coordinate axes and the following linear functions graphically:
(i) $y=-5 x+10$
(ii) $y=2 x-1$
(iii) $y=\frac{1}{2} x-3$
(iv) $y=3 x+\frac{3}{2}$
2. Find the point(s) of intersection of the following functions graphically:
(i) $f(x)=2 x+5, g(x)=-x+5$
(ii) $f(x)=3 x-2, g(x)=10-x$

(iii) $f(x)=2 x-4, g(x)=3 x-1$
(iv) $f(x)=-3 x-4, g(x)=\frac{1}{2} x+3$
(v) $f(x)=x-1, g(x)=x^{2}-4 x+3$
(vi) $f(x)=3 x+4, g(x)=x^{2}+2 x-8$
(vii) $f(x)=-2 x-1, g(x)=x^{2}-4 x$
(viii) $f(x)=-x^{2}-3 x+2, g(x)=x+6$
3. Graph the following functions:
(i) $y=\sqrt{3 x}$
(ii) $y=\sqrt{x}+5$
(iii) $y=-\frac{1}{2} \sqrt{x}$
(iv) $y=-\sqrt{x+1}+2$
(v) $y=\sqrt[3]{2 x+1}$
(vi) $y=2 \sqrt[3]{x}-3$
(vii) $y=\sqrt[3]{x^{2}+x-2}$
4. A building's height over time is modeled by $\mathrm{H}(t)=100+20 t$ which is in metres and $t$ is the time in months. The height of a growing tree nearby is given by $T(t)=50+10 t+t^{2}$.
(i) At what time will the building and tree have the same height?
(ii) What will that height be?

Sketch the graphs of both functions and determine the time when the tree will overtake the height of the building.
5. A radioactive substance has a half-life ( $h$ ) of 2 years. If the initial quantity $Q_{0}$ is 200 grams and the exponential decay function is $Q(t)=Q_{0}\left(\frac{1}{2}\right)^{t}$, then find the remaining quantity after 6 years graphically.

#3 Theory of Quadratic Functions 

## INTRODUCTION

This unit explores methods to find the maximum and minimum values of quadratic functions using completing the square and graphical analysis. It also covers the inverse of quadratic functions, determining their domain and range. Additionally, students will learn to solve absolute value quadratic equations and inequalities, as well as equations of rational, radical and exponential forms that can be reduced to quadratic equations. Finally, the unit demonstrates the practical applications of quadratic equations and inequalities in solving real-world problems, providing a strong foundation for problemsolving and analysis.

### 3.1 Quadratic Function

A quadratic function is a polynomial function of degree two. It is typically expressed in the standard form:

$$
f(x)=a x^{2}+b x+c
$$

where $a, b$ and $c$ are real numbers, and $a \neq 0$.

### 3.1.1 Analyzing Quadratic Fyaction by Sketching

As we know shape of the graph of a quadratic function $f(x)=a x^{2}+b x+c$ is a parabola. The parabola opens upward or downward, depending on the sign of the leading coefficient $a$, as shown in the given figure.
[Image removed]

The tip of the parabola, labeled as $V$ in the diagrams above, is known as the vertex having coordinates $(h, k)$. The vertical line passing through the vertex serves as the axis of symmetry for the parabola. The vertex represents a turning point, where the graph changes direction.

- If $a>0$, then the vertex is a minimum point.
- If $a<0$, then the vertex is a maximum point.

For sketching the quadratic function, we need to find the $x$-intercept, $y$-intercept and the vertex. For analyzing the sketch of quadratic function, we find whether the vertex is a minimum or a maximum point and indicate the intervals where the function is increasing or decreasing.

Example 1 Sketch and analyze $y=-x^{2}-2 x+3$.
Solution $y=-x^{2}-2 x+3$
The $y$-intercept is $y=-(0)^{2}-2(0)+3=3$
The $x$-intercepts are found by solving the equation:

$$
\begin{aligned}
-x^{2}-2 x+3 & =0 \text { or } x^{2}+2 x-3=0 \\
x^{2}+3 x-x-3 & =0 \\
x(x+3)-1(x+3) & =0 \\
(x+3)(x-1) & =0 \\
x+3=0, x-1 & =0 \\
x & =-3, x=1
\end{aligned}
$$

Now, we find the vertex

$$
h=\frac{-b}{2 a}=-\frac{(-2)}{2(-1)}=-1
$$

$k=-(-1)^{2}-2(-1)+3=-1+2+3=4$
So, the vertex $(-1,4)$ is a maximum point. The function $y$ is increasing on $(-\infty,-1)$ and decreasing on $(-1, \infty)$.
[Image removed]

# 3.1.2 Finding Maximum and Minimum Values of Quadratic 

## Functions by Completing Square

Completing the square is a technique used to rewrite a quadratic function $f(x)=a x^{2}+b x+c$ in the following vertex form:

$$
f(x)=a(x-h)^{2}+k
$$

where vertex $=(h, k), h=-\frac{b}{2 a}$ and $k=c-\frac{b^{2}}{4 a}$

- If $a>0$, the minimum value of $f(x)$ at $x=h$ is $k$.
- If $a<0$, the maximum value of $f(x)$ at $x=h$ is $k$.

Example 2 Find the maximum or minimum value of $f(x)=-2 x^{2}+4 x+3$ by completing square.
Solution

$$
\begin{aligned}
& f(x)=-2\left(x^{2}-2 x\right)+3 \\
& f(x)=-2\left(x^{2}-2 x+1-1\right)+3 \\
& f(x)=-2\left[(x-1)^{2}-1\right]+3 \\
& f(x)=-2(x-1)^{2}+2+3 \\
& f(x)=-2(x-1)^{2}+5
\end{aligned}
$$

Here $a=-2<0$
Therefore, the maximum value is 5 , which occurs when $x=1$.
[Image removed]

Example 3 Find the maximum or minimum value of $f(x)=x^{2}-2 x-3$.
Solution Given that $f(x)=x^{2}-2 x-3$
Here $a=1, b=-2, c=-3$

$$
h=-\frac{b}{2 a}=-\frac{(-2)}{2(1)}=1
$$

and

$$
k=c-\frac{b^{2}}{4 a}=-3-\frac{(-2)^{2}}{4(1)}=-4
$$

Here $a=1>0$
Therefore, the minimum value of $f(x)$ at $x=1$ is -4 .

# 3.2 Inverse of Quadratic Function 

[Image removed]

Quadratic functions are typically not one-to-one over their entire domain. To find an inverse for a quadratic function, we must restrict its domain to a portion where it is one-to-one. Commonly, we restrict the domain to either $x \geq h$ (where $h$ is the $x$-coordinate of the vertex) or $x \leq h$.
Example 4 Find the inverse of $f(x)=x^{2}+4 x+3, x \geq-2$. Also find its domain and range.
Solution $f(x)=x^{2}+4 x+3, \quad x \geq-2$
Let

$$
\begin{aligned}
y & =x^{2}+4 x+3 \\
x & =y^{2}+4 y+3 \\
y^{2}+4 y+3-x=0 & \text { (Interchange } x \text { and } y \text { ) } \\
y & =\frac{-4 \pm \sqrt{(4)^{2}-4(1)(3-x)}}{2(1)} \\
y & =\frac{-4 \pm \sqrt{16-12+4 x}}{2} \\
y & =\frac{-4 \pm \sqrt{4+4 x}}{2} \\
y & =\frac{-4 \pm 2 \sqrt{1+x}}{2} \\
f^{-1}(x) & =-2 \pm \sqrt{1+x}
\end{aligned}
$$

(Replace $y$ with $f^{-1}(x)$ )
The above inverse function has both a positive and a negative component. To determine which is the inverse, we find domain and range of the given function.

$$
\text { Domain } f=[-2, \infty)
$$

To find range, we proceed as:

$$
\begin{aligned}
& f(x)=x^{2}+4 x+3 \\
& \Rightarrow \quad f(x)=(x+2)^{2}-1
\end{aligned}
$$

Therefore, minimum value of $f(x)$ is -1 and hence

$$
\text { Range } f=[-1, \infty)
$$

Domain $f^{-1}=[-1, \infty)$, Range $f^{-1}=[-2, \infty)$
Now, we substitute any value of $x$ that falls within the domain of $f^{-1}(x)$. We choose the value $x=0$.

$$
\begin{aligned}
& f^{-1}(0)=-2+\sqrt{1+0}=-1 \\
& f^{-1}(0)=-2-\sqrt{1+0}=-3
\end{aligned}
$$

We notice only -1 lies in the range of $f$. Therefore, we discard negative component.
Hence $f^{-1}(x)=-2+\sqrt{1+x}$

# 3.3 Absolute Value 

The absolute value of $x$, is defined as

$$
|x|=\left\{\begin{array}{ll}
x & , x \geq 0 \\
-x, & x<0
\end{array}\right.
$$

### 3.3.1 Absolute Value Quadratic

[Image removed]

## Equations

To solve the absolute value quadratic equations, all answers must be substituted back into the original equation to verify whether they are valid or not. Sometimes, "extraneous" solutions may appear which are not valid and must be eliminated from the final answer.
Example 5 Solve $\left|x^{2}-4\right|=5$
Solution $\left\{\begin{array}{l}x^{2}-4=5 \\ x^{2}-4= \pm 5\end{array}\right.$

$$
\begin{aligned}
x^{2}-4 & =5 \text { or } x^{2}-4=-5 \\
x^{2} & =9 \text { or } x^{2}=-1 \\
x & = \pm 3 \text { or } x= \pm \sqrt{-1}=\text { imaginary }
\end{aligned}
$$

Check: For $x=3$

$$
\begin{array}{r}
\text { For } \quad x=-3 \\
\left|3^{2}-4\right|=5 \\
|5|=5 \\
5=5
\end{array}\left\lvert\, \begin{array}{l}
\left(-3^{2}\right)-4 \mid=5 \\
|5|=5 \\
5=5
\end{array}\right.
$$

Hence solution set $=\{ \pm 3\}$

# 3.3.2 Absolute Value Quadratic Inequalities 

Absolute value quadratic inequalities are inequalities that involve a quadratic expression within absolute value bars. They are generally of the following forms:
$\left|a x^{2}+b x+c\right|<d,\left|a x^{2}+b x+c\right|>d,\left|a x^{2}+b x+c\right| \leq d,\left|a x^{2}+b x+c\right| \geq d$
Example 6 Solve $\left|x^{2}-6 x-4\right|<3$
Solution $\left|x^{2}-6 x-4\right|<3$
$-3<x^{2}-6 x-4<3$
$-3<x^{2}-6 x-4$
and $\quad x^{2}-6 x-4<3$
$x^{2}-6 x-4+3>0$
and $\quad x^{2}-6 x-4-3<0$
$x^{2}-6 x-1>0$
(i) , $x^{2}-6 x-7<0$
(ii)

Here we solve $x^{2}-6 x-1=0$

$$
\begin{aligned}
& x=\frac{-(-6) \pm \sqrt{(-6)^{2}-4(1)(-1)}}{2(1)} \\
& x=\frac{6 \pm \sqrt{36+4}}{2} \\
& x=\frac{6 \pm \sqrt{40}}{2} \\
& x=\frac{6 \pm 2 \sqrt{10}}{2} \\
& x=3 \pm \sqrt{10} \\
& x=3-\sqrt{10} \quad 3+\sqrt{10} \\
& x=-0.16 \quad 6.16
\end{aligned}
$$

Hence critical values divide the number line into three regions.
[Image removed]

Test $x=-1$ in (i), we have

$$
(-1)^{2}-6(-1)-1>0 \Rightarrow+6>0 \quad \text { (True) }
$$

Test $x=0$ in (i), we have

$$
(0)^{2}-6(0)-1>0 \quad \Rightarrow \quad-1>0 \quad \text { (False) }
$$

Test $x=7$ in (i), we have

$$
(7)^{2}-6(7)-1>0 \quad \Rightarrow \quad 6>0 \quad \text { (True) }
$$

Solution set is $(-\infty, 3-\sqrt{10}) \cup(3+\sqrt{10}, \infty)$

Now, we consider (ii) and solve

$$
\begin{aligned}
x^{2}-6 x-7 & =0 \\
x^{2}+x-7 x-7 & =0 \\
x(x+1)-7(x+1) & =0 \\
(x+1)(x-7) & =0 \\
x+1 & =0, \quad x-7=0 \\
x & =-1, \quad x=7
\end{aligned}
$$

These critical values divide the number line into three regions.
[Image removed]

Solution set is $(-1,7)$
Hence the solution set of the given absolute value quadratic inequality is

$$
\{(-\infty, 3-\sqrt{10}) \cup(3+\sqrt{10}, \infty)\} \cap(-1,7)=(-1,3-\sqrt{10}) \cup(3+\sqrt{10}, 7)
$$

# EXERCISE 3.1 

1. Find the maximum or minimun value of the following quadratic functions by completing square:
(i) $f(x)=x^{2}+6 x+13$
(ii) $f(x)=x^{2}+4 x$
(iii) $f(x)=-x^{2}+8 x+13$
(iv) $f(x)=-x^{2}-3 x-5$
(v) $f(x)=3 x^{2}+6 x-13$
(vi) $f(x)=-2 x^{2}-x+21$
2. Find the maximum or minimum point by sketching the following quadratic functions. Also find their domain and range:
(i) $f(x)=x^{2}-4 x$
(ii) $f(x)=x^{2}-5 x+6$
(iii) $f(x)=-x^{2}+2 x-8$
(iv) $f(x)=x^{2}-4 x+4$
(v) $f(x)=x^{2}+2 x-8.3$
(vi) $f(x)=6-x-x^{2}$
3. Find the inverse of the following quadratic functions. Also find their domain and range:
(i) $f(x)=x^{2}-3, x \leq 0$
(ii) $f(x)=x^{2}+6 x+4, x<-3$
(iii) $f(x)=2 x^{2}-8 x+11, x \geq 2$
(iv) $f(x)=3 x^{2}-2 x+6, x \geq 5$
(v) $f(x)=2(x-3)^{2}+1, x \geq 3$
(vi) $f(x)=-3(x+4)^{2}-5, x<-4$

4. Solve the following absolute value quadratic equations and inequalities:
(i) $\left|x^{2}+1\right|=5$
(ii) $\left|x^{2}+5 x+4\right|=0$
(iii) $\left|x^{2}-6 x+8\right|=4$
(iv) $\left|3 x^{2}-7 x+2\right|=x^{2}-x+1$
(v) $\left|x^{2}-4\right|<5$
(vi) $\left|x^{2}-3 x+2\right|>4$
(vii) $\left|x^{2}-5 x+6\right| \leq x+2$
(viii) $\left|2 x^{2}-3 x-5\right|<4$

# 3.4 Solutions of Equations Reducible to the Quadratic Equation 

There are certain types of equations, which do not look to be of degree 2 , but they can be reduced to the quadratic equation. We shall discuss the solutions of the rational and radical equations.

### 3.4.1 Rational Equations Reducible to the Quadratic Equation

A rational equation is an equation containing one or more rational expressions, where rational expressions typically contain a variable in the denominator.
Example 7 Solve $\frac{1}{x}+\frac{2}{x+1}=1, x \neq 0, x \neq-1$
Solution $\frac{1}{x}+\frac{2}{x+1}=1$
Multiplying both sides by $x(x+1)$, we have

$$
\begin{aligned}
(x+1)+2 x & =x(x+1) \\
x+1+2 x & =x^{2}+x \\
3 x+1 & =x^{2}+x \\
x^{2}+x-3 x-1 & =0 \\
x^{2}-2 x-1 & =0 \\
x & =\frac{-(-2) \pm \sqrt{(-2)^{2}-4(1)(-1)}}{2(1)} \\
& =\frac{2 \pm \sqrt{4+4}}{2} \\
x & =\frac{2 \pm \sqrt{8}}{2} \\
& =\frac{2 \pm 2 \sqrt{2}}{2} \\
& =1 \pm \sqrt{2}
\end{aligned}
$$

Hence, Solution Set $=\{1 \pm \sqrt{2}\}$

# 3.4.2 Radical Equations Reducible to the Quadratic Equation 

Equations involving radical expressions of the variable are called radical equations. To solve a radical equation, we first obtain an equation free from radicals. Every solution of radical equation is also a solution of the radical-free equation but the new equation has solutions that are not solutions of the original radical equation. Such extra solutions (roots) are called extraneous roots.
Example 8 Solve $\sqrt{x+8}+\sqrt{x+3}=\sqrt{12 x+13}$
Solution $\sqrt{x+8}+\sqrt{x+3}=\sqrt{12 x+13}$
Squaring both sides, we get

$$
\begin{aligned}
x+8+x+3+2(\sqrt{x+8})(\sqrt{x+3}) & =12 x+13 \\
2(\sqrt{x+8})(\sqrt{x+3}) & =10 x+2 \\
\Rightarrow \quad \sqrt{(x+8)(x+3)} & =5 x+1
\end{aligned}
$$

Squaring again, we have

$$
\begin{aligned}
x^{2}+11 x+24 & =25 x^{2}+10 x+1 \\
\Rightarrow \quad 24 x^{2}-x-23 & =0 \\
\Rightarrow \quad(24 x+23)(x-1) & =0 \\
x & =-\frac{23}{24} \text { or } x=1
\end{aligned}
$$

On checking we find that $-\frac{23}{24}$ is an extraneous root. Hence solution set $=\{1\}$

### 3.5 Real World Problems of Quadratic Equations and Inequalities

We shall now proceed to solve the problems which, when expressed symbolically, lead to quadratic equations in one variables.
In order to solve such problems, we must:
(i) Suppose the unknown quantities to be $x$ or $y$ etc.
(ii) Translate the problem into symbols and form the equation or inequality satisfying the given conditions.
The method of solving the problems will be illustrated through the following examples:

Example 9 The length of a room is 3 metres greater than its breadth. If the area of the room is 180 square metres, find length and the breadth of the room.
Solution Let the breadth of room $=x$ metres
and the length of room $=(x+3)$ metres
$\therefore \quad$ Area of the room $=x(x+3)$ square metres
By the given condition, we have

$$
\begin{aligned}
x(x+3) & =180 \\
\Rightarrow \quad x^{2}+3 x-180 & =0 \\
\Rightarrow \quad(x+15)(x-12) & =0 \\
\therefore \quad x=-15 \text { or } x & =12
\end{aligned}
$$

As breadth cannot be negative so $x=-15$ is not admissible.
When $x=12$, we get $x+3=12+3=15$
Hence breadth of the room $=12$ metres and length of the room $=15$ metres.
Example 10 A company manufactures laptops and its weekly profit function (in thousands of dollars) is $P(x)=-x^{2}+2 x+3$, where $x$ is the number of laptops produced (in hundreds). Find the range of production levels where the company makes at least $\$ 4,000$ profit.
Solution Here $P(x) \geq 4$

$$
\begin{aligned}
& -x^{2}+2 x+3 \geq 4 \\
& -x^{2}+2 x+3-4 \geq 0 \\
& -x^{2}+2 x-1 \geq 0 \\
& x^{2}-2 x+1 \leq 0 \\
& (x-1)^{2} \leq 0
\end{aligned}
$$

This only holds true when $(x-1)^{2}=0 \Rightarrow x=1$
The company makes exactly $\$ 4,000$ profit when 100 laptops are produced (since $x=1$ means 100 laptops). There is no production level where profit is more than $\$ 4,000$.

# EXERCISE 3.2 

1. Solve the following equations:
(i) $\frac{1}{3 x}+\frac{4 x}{6}=1, x \neq 0$
(ii) $\frac{x}{x+1}+\frac{x+1}{x}=\frac{5}{2} ; x \neq-1,0$
(iii) $\frac{1}{x+1}+\frac{2}{x+2}=\frac{7}{x+5} ; x \neq-1,-2,-5$

(iv) $\frac{a}{a x-1}+\frac{b}{b x-1}=a+b ; x \neq \frac{1}{a}, \frac{1}{b}$
(v) $\frac{x+1}{x-1}+\frac{x-1}{x+1}=2, x \neq 1, x \neq-1$
(vi) $3 x^{2}+15 x-2 \sqrt{x^{2}+5 x+1}=2$
(vii) $\sqrt{2 x+8}+\sqrt{x+5}=7$
(viii) $\sqrt{3 x+4}=2+\sqrt{2 x-4}$
(ix) $\sqrt{x+7}+\sqrt{x+2}=\sqrt{6 x+13}$
(x) $\sqrt{x+5}-\sqrt{x-3}=2$

2 A farmer bought some sheep for Rs. 9000. If he had paid Rs. 100 less for each, he would have got 3 sheep more for the same money. How many sheep did he buy, when the rate in each case is uniform?
3. A man sold his stock of eggs for Rs. 2400. If he had 2 dozen more, he would have got the same money by selling the whole for Rs. 0.50 per dozen cheaper. How many dozen eggs did he sell?
4. A cyclist travelled 48 km at a uniform speed. If he had travelled $2 \mathrm{~km} /$ hour slower, he would have taken 2 hours more to perform the journey. How long did he take to cover 48 km ?
5. To do a piece of work, Abdullah takes 10 days more than Abdul Hadi. Together they finish the work in 12 days. How long would Abdul Hadi take to finish it alone?
6. The braking distance (in metres) of a car is modeled by:
$d(s)=0.02 s^{2}+0.1 s$, where $s$ is the speed of car in $\mathrm{km} / \mathrm{h}$
If the maximum safe braking distance is 50 metres, find the range of speed where braking is safe.
7. A rocket follows the height function $h(t)=-5 t^{2}+20 t+30$, where $h(t)$ is the height in metres and $t$ is the time in seconds. Find the time interval during which the rocket is at least 40 metres above the ground.

# 4 

# Matrices and Determinants

## INTRODUCTION

This unit introduces the fundamental concepts and operations of matrices, equipping students with the skills to perform matrix addition, subtraction and multiplication involving both real and complex entries. It explores the essential properties of determinants and provides techniques for evaluating the determinant of a $3 \times 3$ matrix using cofactors and determinant properties. Students will learn to apply row operations to determine the inverse and rank of matrices, as well as distinguish between consistent and inconsistent systems of linear equations through practical examples. The unit further explores into solving systems of linear equations, both homogeneous and non-homogeneous, using advanced methods such as matrix inversion, Cramer's Rule and Gaussian elimination. Emphasis is placed on the realworld applications of matrices in diverse fields such as graphic design, cryptography, data encryption, geometric transformations and highlighting the importance and versatility of matrix algebra in solving complex, practical problems.

### 4.1 Matrix

While solving linear systems of equations, a new notation was introduced to reduce the amount of writing. For this new notation the word matrix was first used by the English mathematician James Sylvester (1814 - 1897). Arthur Cayley (1821 - 1895) developed the theory of matrices and used them in the linear transformations. Now-adays, matrices are used in high speed computers and also in other various disciplines. The concept of determinants was used by Chinese and Japanese mathematicians but the Japanese mathematician Seki Kowa (1642-1708) and the German Mathematician Gottfried Wilhelm Leibniz (1646-1716) are credited for the invention of determinants. G. Cramer (1704-1752) employed the determinants successfully for solving the systems of linear equations.
A rectangular array of numbers enclosed by a pair of bracket is called a matrix such as:

$$
\left[\begin{array}{ccc}
2 & -1 & 3 \\
-5 & 4 & 7
\end{array}\right] \quad \text { (i) } \quad \text { or } \quad\left[\begin{array}{ccc}
2 & 3 & 0 \\
1 & -1 & 4 \\
3 & 2 & 6 \\
4 & 1 & -1
\end{array}\right]
$$

called columns. The numbers used in rows or columns are said to be the entries or elements of the matrix.
The matrix in (i) has two rows and three columns while the matrix in (ii) has four rows and three columns. Note that the number of the elements of the matrix in (ii) is $4 \times 3=12$. Now the general definition of a matrix is:
Generally, a bracketed rectangular array of $m \cdot n$ elements $a_{i j}\left(1,2,3, \ldots, m\right.$; $j=1,2,3, \ldots, n$ ), arranged in $m$ rows and $n$ columns such as:
[Image removed]
is called an $m$ by $n$ matrix (written as $m \times n$ matrix), where $m \times n$ is called the order of the matrix in (iii). The matrices are usually represented by the capital letters such as $A, B, C, X, Y$, etc., and small letters such as $a, b, c, l, m, n$, or $a_{11}, a_{12}, a_{13}, \ldots$, etc., are used to indicate the entries of the matrices.
Let the matrix in (iii) be denoted by $A$. The $i$ th row and the $j$ th column of $A$ are indicated in the following tabular representation of $A$.
[Image removed]

The elements of the $i$ th row of $A$ are $a_{i 1} a_{i 2} a_{i 3} \ldots a_{i j} \ldots a_{i n}$ while the elements of the $j$ th column of $A$ are $a_{1 j} a_{2 j} a_{3 j} \ldots a_{i j} \ldots a_{m j}$. We note that $a_{i j}$ is the element of the $i$ th row and $j$ th column of $A$. The double subscripts are useful to name the elements of the matrices. For example, the element 7 is at $a_{23}$ position in the matrix $\left[\begin{array}{ccc}2 & -1 & 3 \\ -5 & 4 & 7\end{array}\right]$. For convenience, we shall write the matrix $A$ as:

$A=\left[a_{i j}\right]_{m \times n}$ or $A=\left[a_{i j}\right]$, for $i=1,2,3, \ldots, m ; j=1,2,3, \ldots, n$, where $a_{i j}$ is the element of the $i$ th row and $j$ th column of $A$.
The elements (entries) of matrices need not always be numbers but in the study of matrices, we shall take the elements of the

## Note

The matrix $A$ is called real matrix if all of its elements are real.
matrices from $R$ or $C$.
Row Matrix or Row vector: A matrix, which has only one row, i.e., $1 \times n$ matrix of the form $\left[\begin{array}{llll}a_{i 1} & a_{i 2} & a_{i 3} & \ldots & a_{i n}\end{array}\right]$ is said to be a row matrix or a row vector.
Column Matrix or Column Vector: A matrix which has only one column i.e., an $m \times 1$ matrix of the form $\left[\begin{array}{c}a_{1 j} \\ a_{2 j} \\ a_{3 j} \\ \vdots \\ a_{m j}\end{array}\right]$ is said to be a column matrix or a column vector.

For example [1-1 3 4] is a row matrix having 4 columns and $\left[\begin{array}{l}2 \\ -1 \\ 3\end{array}\right]$ is a column matrix having 3 rows.
Rectangular Matrix: If $m \neq n$, then the matrix is called a rectangular matrix of order $m \times n$, that is, the matrix in which the number of rows is not equal to the number of columns, is said to be a rectangular matrix. For example;
$\left[\begin{array}{lll}2 & 3 & 1 \\ -1 & 0 & 4\end{array}\right]$ and $\left[\begin{array}{rrr}2 & -3 & 0 \\ 1 & 2 & 4 \\ 3 & -1 & 5 \\ 0 & 1 & 2\end{array}\right]$ are rectangular matrices of orders $2 \times 3$ and $4 \times 3$ respectively.
Square Matrix: If $m=n$, then the matrix of order $m \times n$ is said to be a square matrix of order $n$ or $m$. i.e., the matrix which has the same number of rows and columns is called a square matrix. For example: $[0],\left[\begin{array}{rr}2 & 5 \\ -1 & 6\end{array}\right]$ and $\left[\begin{array}{rrr}1 & 1 & 2 \\ 2 & -1 & 8 \\ 3 & 5 & 4\end{array}\right]$ are square matrices of orders 1,2 and 3 respectively.

Let $A=\left[a_{i j}\right]$ be a square matrix of order $n$, then the entries $a_{11}, a_{22}, a_{33}, \ldots, a_{n n}$ form the principal diagonal for the matrix $A$ and the entries $a_{1 n}, a_{2 n-1}, a_{3 n-2}, \ldots, a_{n-12}, a_{n 1}$ form the secondary diagonal for the matrix $A$. For example, in the matrix

$$
\left[\begin{array}{llll}
a_{11} & a_{12} & a_{13} & a_{14} \\
a_{21} & a_{22} & a_{23} & a_{24} \\
a_{31} & a_{32} & a_{33} & a_{34} \\
a_{41} & a_{42} & a_{43} & a_{44}
\end{array}\right], \text { the entries of the principal diagonal are } a_{11}, a_{22}, a_{33}, a_{44} \text { and the }
$$

entries of the secondary diagonal are $a_{14}, a_{23}, a_{32}, a_{41}$.
The principal diagonal of a square matrix is also called the leading diagonal or main diagonal of the matrix.
Diagonal Matrix: Let $A=\left[a_{i j}\right]$ be a square matrix of order $n$.
If $a_{i j}=0$ for all $i \neq j$ and at least one $a_{i j} \neq 0$ for $i=j$, that is, some elements of the principal diagonal of $A$ may be zero but not all, then the matrix $A$ is called a diagonal matrix. The matrices

$$
[7],\left[\begin{array}{lll}
1 & 0 & 0 \\
0 & 2 & 0 \\
0 & 0 & 5
\end{array}\right] \text { and }\left[\begin{array}{llll}
0 & 0 & 0 & 0 \\
0 & 1 & 0 & 0 \\
0 & 0 & 2 & 0 \\
0 & 0 & 0 & 4
\end{array}\right] \text { are diagonal matrices. }
$$

Scalar Matrix: Let $A=\left[a_{i j}\right]$ be a square matrix of order $n$.
If $a_{i j}=0$ for all $i \neq j$ and $a_{i j}=k$ (some non-zero scalar) for all $i=j$, then the matrix $A$ is called a scalar matrix of order $n$. For example:
$\left[\begin{array}{ll}7 & 0 \\ 0 & 7\end{array}\right],\left[\begin{array}{llll}a & 0 & 0 \\ 0 & a & 0 \\ 0 & 0 & a\end{array}\right](a \neq 0)$ and $\left[\begin{array}{llll}3 & 0 & 0 & 0 \\ 0 & 3 & 0 & 0 \\ 0 & 0 & 3 & 0 \\ 0 & 0 & 0 & 3\end{array}\right]$ are scalar matrices of order 2,3 and 4 respectively.
Unit Matrix or Identity Matrix: Let $A=\left[a_{i j}\right]$ be a square matrix of order $n$. If $a_{i j}=0$ for all $i \neq j$ and $a_{i j}=1$ for all $i=j$, then the matrix $A$ is called a unit matrix or identity matrix of order $n$. We denote such a matrix by $I_{n}$ or simply $I$ and it is of the form:

$$
I_{n}=\left[\begin{array}{ccccc}
1 & 0 & 0 & \cdots & 0 \\
0 & 1 & 0 & \cdots & 0 \\
0 & 0 & 1 & \cdots & 0 \\
\vdots & \vdots & \vdots & & \vdots \\
0 & 0 & 0 & \cdots & 1
\end{array}\right]
$$

The identity matrix of order 3 is denoted by $I_{3}$, that is, $I_{3}=\left[\begin{array}{lll}1 & 0 & 0 \\ 0 & 1 & 0 \\ 0 & 0 & 1\end{array}\right]$
Null Matrix or Zero Matrix: A square or rectangular matrix whose each element is zero, is called a null or zero matrix. An $m \times n$ matrix with all its elements equal to zero, is denoted by $O_{m \times n}$. Null matrices may be of any order. Here are some examples:
$[0],\left[\begin{array}{llll}0 & 0 & 0 & 0\end{array}\right],\left[\begin{array}{llll}0 & 0 & 0 \\ 0 & 0 & 0\end{array}\right],\left[\begin{array}{lll}0 & 0 \\ 0 & 0\end{array}\right],\left[\begin{array}{l}0 \\ 0 \\ 0\end{array}\right],\left[\begin{array}{llll}0 & 0 & 0 & 0 \\ 0 & 0 & 0 & 0\end{array}\right]$
Note
$O$ may be used to denote null matrix of any order if there is no confusion.
are null matrices of order $1,1 \times 3,2 \times 3,2 \times 2,3 \times 1,3 \times 4$ respectively.
Equal Matrices: Two matrices of the same order are said to be equal if their corresponding entries are equal. For example, $A=\left[a_{i j}\right]_{m \times n}$ and $B=\left[b_{i j}\right]_{m \times n}$ are equal, i.e., $A=B$ iff $a_{i j}=b_{i j}$ for $i=1,2,3, \ldots, m, j=1,2,3, \ldots, n$. In other words, $A$ and $B$ represent the same matrix.
Transpose of a Matrix: If $A$ is a matrix of order $m \times n$ then an $n \times m$ matrix obtained by interchanging the rows and columns of $A$, is called the transpose of $A$. It is denoted by $A^{t}$. Let $A=\left[a_{i j}\right]_{m \times n}$, then the transpose of $A$ is defined as:

$$
A^{t}=\left[a_{i j}^{t}\right]_{m \times n} \text { where } a_{i j}^{t}=a_{j i} \text { for } i=1,2,3, \ldots, n \text { and } j=1,2,3, \ldots, m
$$

For example, if $B=\left[b_{i j}\right]_{3 \times 4}=\left[\begin{array}{llll}b_{11} & b_{12} & b_{13} & b_{14} \\ b_{21} & b_{22} & b_{23} & b_{24} \\ b_{31} & b_{32} & b_{33} & b_{34}\end{array}\right]$, then
$B^{t}=\left[b_{i j}^{t}\right]_{4 \times 3}$ where $b_{i j}^{t}=b_{j i}$ for $i=1,2,3,4$ and $j=1,2,3$ i.e.,

$$
B^{t}=\left[\begin{array}{lll}
b_{11}^{t} & b_{12}^{t} & b_{13}^{t} \\
b_{21}^{t} & b_{22}^{t} & b_{23}^{t} \\
b_{31}^{t} & b_{32}^{t} & b_{33}^{t} \\
b_{41}^{t} & b_{42}^{t} & b_{43}^{t}
\end{array}\right]=\left[\begin{array}{lll}
b_{11} & b_{21} & b_{31} \\
b_{12} & b_{22} & b_{32} \\
b_{13} & b_{23} & b_{33} \\
b_{14} & b_{24} & b_{34}
\end{array}\right]
$$

Note that the $2^{\text {nd }}$ row of $B$ has the same entries respectively as the $2^{\text {nd }}$ column of $B^{t}$ and the $3^{\text {rd }}$ row of $B^{t}$ has the same entries respectively as the $3^{\text {rd }}$ column of $B$ etc.

# 4.2 Matrix Operations 

Matrix operations involve various techniques and procedures applied to matrices. These operations are foundational in linear algebra and have applications in numerous fields such as computer graphics, physics, statistics, etc. Here are some key matrix operations:

### 4.2.1 Addition of Matrices

Two matrices are conformable for addition if they are of the same order.
The sum $A+B$ of two $m \times n$, matrices $A=\left[a_{i j}\right]$ and $B=\left[b_{i j}\right]$ is the $m \times n$ matrix $C=\left[c_{i j}\right]$ formed by adding the corresponding entries of $A$ and $B$ together. In symbols, we write as $C=A+B$, that is:

$$
\left[c_{i j}\right]=\left[a_{i j}+b_{i j}\right] \text { where } c_{i j}=a_{i j}+b_{i j} \text { for } i=1,2,3, \ldots, m ; j=1,2,3, \ldots, n
$$

### 4.2.2 Subtraction of Matrices

If $A=\left[a_{i j}\right]$ and $B=\left[b_{i j}\right]$ are matrices of order $m \times n$, then we define subtraction of $B$ from $A$ as:

$$
\begin{aligned}
A-B & =A+(-B) \\
& =\left[a_{i j}\right]+\left[-b_{i j}\right]=\left[a_{i j}+\left(-b_{i j}\right)\right]=\left[a_{i j}-b_{i j}\right] \text { for } i=1,2,3, \ldots, m ; j=1,2,3, \ldots, n
\end{aligned}
$$

Thus, the matrix $A-B$ is formed by subtracting each entry of $B$ from the corresponding entry of $A$.

Example 1 If $A=\left[\begin{array}{cccc}1 & 0 & -1 & 2 \\ 3 & 1 & 2 & 5 \\ 0 & -2 & 1 & 6\end{array}\right]$ and $B=\left[\begin{array}{cccc}2 & -1 & 3 & 1 \\ 1 & 3 & -1 & 4 \\ 3 & 1 & 2 & -1\end{array}\right]$, then show that

$$
(A+B)^{t}=A^{t}+B^{t}
$$

## Solution

$A+B=\left[\begin{array}{cccc}1 & 0 & -1 & 2 \\ 3 & 1 & 2 & 5 \\ 0 & -2 & 1 & 6\end{array}\right]+\left[\begin{array}{cccc}2 & -1 & 3 & 1 \\ 1 & 3 & -1 & 4 \\ 3 & 1 & 2 & -1\end{array}\right]=\left[\begin{array}{cccc}1+2 & 0+(-1) & -1+3 & 2+1 \\ 3+1 & 1+3 & 2+(-1) & 5+4 \\ 0+3 & -2+1 & 1+2 & 6+(-1)\end{array}\right]$
$=\left[\begin{array}{cccc}3 & -1 & 2 & 3 \\ 4 & 4 & 1 & 9 \\ 3 & -1 & 3 & 5\end{array}\right]$
and $(A+B)^{t}=\left[\begin{array}{ccc}3 & 4 & 3 \\ -1 & 4 & -1 \\ 2 & 1 & 3 \\ 3 & 9 & 5\end{array}\right]$
(i)

Taking transpose of $A$ and $B$, we have

$$
\begin{gathered}
A^{t}=\left[\begin{array}{ccc}
1 & 3 & 0 \\
0 & 1 & -2 \\
-1 & 2 & 1 \\
2 & 5 & 6
\end{array}\right] \text { and } B^{t}=\left[\begin{array}{ccc}
2 & 1 & 3 \\
-1 & 3 & 1 \\
3 & -1 & 2 \\
1 & 4 & -1
\end{array}\right] \\
\Rightarrow \quad A^{t}+B^{t}=\left[\begin{array}{ccc}
1 & 3 & 0 \\
0 & 1 & -2 \\
-1 & 2 & 1 \\
2 & 5 & 6
\end{array}\right]+\left[\begin{array}{ccc}
2 & 1 & 3 \\
-1 & 3 & 1 \\
3 & -1 & 2 \\
1 & 4 & -1
\end{array}\right]=\left[\begin{array}{ccc}
3 & 4 & 3 \\
-1 & 4 & -1 \\
2 & 1 & 3 \\
3 & 9 & 5
\end{array}\right]
\end{gathered}
$$

From (i) and (ii), we have $(A+B)^{t}=A^{t}+B^{t}$

# 4.2.3 Scalar Multiplication 

If $A=\left[a_{i j}\right]$ is $m \times n$ matrix and $k$ is a real or complex number, then the product of $k$ and $A$, denoted by $k A$, is the matrix formed by multiplying each entry of $A$ by $k$, that is
$k A=\left[k a_{i j}\right]$
Obviously, order of $k A$ is $m \times n$.

### 4.2.4 Multiplication of two Matrices

## Note

If $n$ is a positive integer, then $A+A+A+\cdots$ to $n$ terms $=n A$.

Two matrices $A$ and $B$ are said to be conformable for the product $A B$ if the number of columns of $A$ is equal to the number of rows of $B$.
Let $A=\left[a_{i j}\right]$ be a $2 \times 3$ matrix and $B=\left[b_{i j}\right]$ be a $3 \times 2$ matrix, then the product $A B$ is defined to be the $2 \times 2$ matrix $C$ whose element $c_{i j}$ is the sum of products of the corresponding elements of the $i$ th row of $A$ with elements of $j$ th column of $B$. For example, the element $c_{21}$ of $C$ is shown in the figure (A), that is
[Image removed]

Figure (A)
$c_{21}=a_{21} b_{11}+a_{22} b_{21}+a_{23} b_{31}$. Thus
$A B=\left[\begin{array}{lll}a_{11} & a_{12} & a_{13} \\ a_{21} & a_{22} & a_{23}\end{array}\right]\left[\begin{array}{lll}b_{11} & b_{12} \\ b_{21} & b_{22} \\ b_{31} & b_{32}\end{array}\right]=\left[\begin{array}{lll}a_{11} b_{11}+a_{12} b_{21}+a_{13} b_{31} & a_{11} b_{12}+a_{12} b_{22}+a_{13} b_{32} \\ a_{21} b_{11}+a_{22} b_{21}+a_{23} b_{31} & a_{21} b_{12}+a_{22} b_{22}+a_{23} b_{32}\end{array}\right]$

Similarly $B A=\left[\begin{array}{lll}b_{11} & b_{12} \\ b_{21} & b_{22} \\ b_{31} & b_{32}\end{array}\right]\left[\begin{array}{lll}a_{11} & a_{12} & a_{13} \\ a_{21} & a_{22} & a_{23}\end{array}\right]$

$$
=\left[\begin{array}{lll}
b_{11} a_{11}+b_{12} a_{21} & b_{11} a_{12}+b_{12} a_{22} & b_{11} a_{13}+b_{12} a_{23} \\
b_{21} a_{11}+b_{22} a_{21} & b_{21} a_{12}+b_{22} a_{22} & b_{21} a_{13}+b_{22} a_{23} \\
b_{31} a_{11}+b_{32} a_{21} & b_{31} a_{12}+b_{32} a_{22} & b_{31} a_{13}+b_{32} a_{23}
\end{array}\right]
$$

From (i) and (ii), $A B$ and $B A$ are calculated their orders are $2 \times 2$ and $3 \times 3$ respectively.
Note1. In general, $A B \neq B A$
Note 2. If the product $A B$ is defined, then the order of the product can be illustrated as given below:

Order of $A$
Order of $B$
Order of $A B$
[Image removed]

Example 2 If $A=\left[\begin{array}{rrr}2 & -1 & 0 \\ 1 & 2 & -3 \\ 1 & 2 & -2\end{array}\right]$ and $B=\left[\begin{array}{rrr}2 & -2 & 3 \\ -1 & -4 & 6 \\ 0 & -5 & 5\end{array}\right]$, then compute $A^{2} B$.

Solution

$$
\begin{aligned}
A^{2} & =A \cdot A=\left[\begin{array}{rrr}
2 & -1 & 0 \\
1 & 2 & -3 \\
1 & 2 & -2
\end{array}\right]\left[\begin{array}{rrr}
2 & -1 & 0 \\
1 & 2 & -3 \\
1 & 2 & -2
\end{array}\right] \\
& =\left[\begin{array}{rrr}
4-1+0 & -2-2+0 & 0+3+0 \\
2+2-3 & -1+4-6 & 0-6+6 \\
2+2-2 & -1+4-4 & 0-6+4
\end{array}\right]=\left[\begin{array}{rrr}
3 & -4 & 3 \\
1 & -3 & 0 \\
2 & -1 & -2
\end{array}\right] \\
\therefore \quad A^{2} B & =\left[\begin{array}{rrr}
3 & -4 & 3 \\
1 & -3 & 0 \\
2 & -1 & -2
\end{array}\right]\left[\begin{array}{rrr}
2 & -2 & 3 \\
-1 & -4 & 6 \\
0 & -5 & 5
\end{array}\right] \\
& =\left[\begin{array}{rrr}
6+4+0 & -6+16-15 & 9-24+15 \\
2+3+0 & -2+12+0 & 3-18+0 \\
4+1+0 & -4+4+10 & 6-6-10
\end{array}\right]=\left[\begin{array}{rrr}
10 & -5 & 0 \\
5 & 10 & -15 \\
5 & 10 & -10
\end{array}\right]
\end{aligned}
$$

Note: Powers of square matrices are defined as:

$$
\begin{aligned}
& A^{2}=A \times A, A^{3}=A \times A \times A \\
& A^{n}=A \times A \times A \times \cdots \text { to } n \text { factors. }
\end{aligned}
$$

# 4.3 Properties of Matrix Addition, Scalar Multiplication and Matrix Multiplication 

If $A, B$ and $C$ are conformable for the indicated sum or product of matrices and $c$ and $d$ are scalars, then following properties are true:
(i) Commutative property w.r.t. addition: $A+B=B+A$
(ii) Associative property w.r.t. addition: $(A+B)+C=A+(B+C)$
(iii) Associative property of scalar multiplication: $(c d) A=c(d A)$
(iv) Existence of additive identity: $A+O=O+A=A \quad \begin{cases}O \text { is null matrix and } \\ A \text { is a square matrix }\end{cases}$
(v) Existence of multiplicative identity: $I A=A I=A \quad$ (I is unit/identity matrix)
(vi) Distributive property w.r.t scalar multiplication:
(a) $c(A+B)=c A+c B$
(b) $(c+d) A=c A+d A$
(vii) Associative property w.r.t. multiplication: $A(B C)=(A B) C$
(viii) Left distributive property: $A(B+C)=A B+A C$
(ix) Right distributive property: $(A+B) C=A C+B C$
(x) $c(A B)=(c A) B=A(c B)$

Example 3 Find $A B$ and $B A$ if $A=\left[\begin{array}{lll}2 & 0 & 1 \\ 1 & 4 & 2 \\ 3 & 0 & 6\end{array}\right]$ and $B=\left[\begin{array}{rrr}1 & -1 & 0 \\ 2 & 3 & -1 \\ 1 & -2 & 3\end{array}\right]$
Solution $A B=\left[\begin{array}{lll}2 & 0 & 1 \\ 1 & 4 & 2 \\ 3 & 0 & 6\end{array}\right]\left[\begin{array}{rrr}1 & -1 & 0 \\ 2 & 3 & -1 \\ 1 & -2 & 3\end{array}\right]$

$$
\begin{aligned}
& =\left[\begin{array}{rrr}
2 \times 1+0 \times 2+1 \times 1 & 2 \times(-1)+0 \times 3+1 \times(-2) & 2 \times 0+0 \times(-1)+1 \times 3 \\
1 \times 1+4 \times 2+2 \times 1 & 1 \times(-1)+4 \times 3+2 \times(-2) & 1 \times 0+4 \times(-1)+2 \times 3 \\
3 \times 1+0 \times 2+6 \times 1 & 3 \times(-1)+0 \times 3+6 \times(-2) & 3 \times 0+0 \times(-1)+6 \times 3
\end{array}\right] \\
& =\left[\begin{array}{rrr}
3 & -4 & 3 \\
11 & 7 & 2 \\
9 & -15 & 18
\end{array}\right] \\
& B A=\left[\begin{array}{rrr}
1 & -1 & 0 \\
2 & 3 & -1 \\
1 & -2 & 3
\end{array}\right]\left[\begin{array}{lll}
2 & 0 & 1 \\
1 & 4 & 2 \\
3 & 0 & 6
\end{array}\right]
\end{aligned}
$$

$$
\begin{aligned}
& =\left[\begin{array}{l}
1 \times 2+(-1) \times 1+0 \times 3 \quad 1 \times 0+(-1) \times 4+0 \times 0 \quad 1 \times 1+(-1) \times 2+0 \times 6 \\
2 \times 2+3 \times 1+(-1) \times 3 \quad 2 \times 0+3 \times 4+(-1) \times 0 \quad 2 \times 1+3 \times 2+(-1) \times 6 \\
1 \times 2+(-2) \times 1+3 \times 3 \quad 1 \times 0+(-2) \times 4+3 \times 0 \quad 1 \times 1+(-2) \times 2+3 \times 6
\end{array}\right] \\
& =\left[\begin{array}{rrr}
1 & -4 & -1 \\
4 & 12 & 2 \\
9 & -8 & 15
\end{array}\right]
\end{aligned}
$$

Note
Matrix multiplication is not commutative in general.

Thus, from (i) and (ii), $A B \neq B A$

# EXERCISE 4.1 

1. If $A=\left[a_{i j}\right]_{i=1}$, then show that
(i) $I_{2} A=A$
(ii) $A I_{4}=A$
2. If $A=\left[\begin{array}{lll}0 & -1 & 2 \\ 3 & 2 & 1 \\ -1 & 0 & 4\end{array}\right], B=\left[\begin{array}{llll}2 & 1 & -1 \\ 1 & 2 & 4 \\ -1 & 2 & 1\end{array}\right]$ and $C=\left[\begin{array}{llll}1 & 0 & -2 \\ -1 & 5 & 0 \\ 3 & 4 & -1\end{array}\right]$, then find
(i) $A-B$
(ii) B-C
(iii) $(A-B)-C$
(iv) $A-(B-C)$
3. If $A=\left[\begin{array}{lll}i & 2 i \\ 1 & -i\end{array}\right], B=\left[\begin{array}{cc}-i & 1 \\ 2 i & 1\end{array}\right]$ and $C=\left[\begin{array}{cc}2 i & 1 \\ -i & i\end{array}\right]$, then show that
(i) $(A B) C=A(B C)$
(ii) $A(B+C)=A B+A C$
4. If $A$ and $B$ are square matrices of the same order, then explain why in general;
(i) $(A+B)^{2} \neq A^{2}+2 A B+B^{2}$
(ii) $(A-B)^{2} \neq A^{2}-2 A B+B^{2}$
(iii) $(A+B)(A-B) \neq A^{2}-B^{2}$
5. If $A=\left[\begin{array}{ccc}-1 & 2 & 3 \\ 1 & 0 & 2 \\ -3 & 5 & 3\end{array}\right]$, then find $A+A^{t}, A-A^{t}, A A^{t}, A^{t} A$ and $\left(A^{t}\right)^{t}$.
6. Solve the matrix equation $A^{2}-5 A+4 I-X=0$ if $A=\left[\begin{array}{lll}2 & 0 & 1 \\ 2 & 1 & 3 \\ 1 & -1 & 0\end{array}\right]$
7. If $A$ and $B$ are two matrices such that $A B=B$ and $B A=A$, show that $A^{2}+B^{2}=A+B$.

### 4.4 Determinants

The determinants of square matrices of order $n \geq 3$, can be written by the following pattern. For example, if $n=3$

$A=\left[\begin{array}{lll}a_{11} & a_{12} & a_{13} \\ a_{21} & a_{22} & a_{23} \\ a_{31} & a_{32} & a_{33}\end{array}\right]$, then the determinant of $A=|A|=\left|\begin{array}{lll}a_{11} & a_{12} & a_{13} \\ a_{21} & a_{22} & a_{23} \\ a_{31} & a_{32} & a_{33}\end{array}\right|$
Now our aim is to compute the determinants of matrices of various orders.

# 4.4.1 Minor and Cofactor of an Element of a Matrix or its Determinant Minor of an Element: Let us consider a square matrix $A$ of order $n$, then the minor of an element $a_{i j}$, denoted by $M_{i j}$ is the determinant formed by deleting the $i$ th row and the $j$ th column of $A($ or $|A|)$.

For example, consider a square matrix $A$ of order $3, A=\left[\begin{array}{llll}a_{11} & a_{13} & a_{13} \\ a_{21} & a_{22} & a_{23} \\ a_{31} & a_{32} & a_{33}\end{array}\right]$
To find the minor of the element $a_{12}$, delete the first row and second column of $A$

$$
\left[\begin{array}{lll}
a_{11} & a_{12} & a_{13} \\
a_{21} & a_{22} & a_{23} \\
a_{31} & a_{32} & a_{33}
\end{array}\right], \text { that is } M_{12}=\left|\begin{array}{ll}
a_{21} & a_{23} \\
a_{31} & a_{33}
\end{array}\right|
$$

Cofactor of an Element: The cofactor of an element $a_{i j}$ of a square matrix $A$ denoted by $A_{i j}$ is defined by $A_{i j}=(-1)^{i+j} M_{i j}$
For example, $A_{12}=(-1)^{1 / 2} M_{13}=(-1)^{3}\left|\begin{array}{ll}a_{21} & a_{23} \\ a_{31} & a_{33}\end{array}\right|=-\left|\begin{array}{ll}a_{21} & a_{23} \\ a_{31} & a_{33}\end{array}\right|$

### 4.4.2 Determinant of a Square Matrix of Order $n=3$

If $A$ is a matrix of order 3 , that is, $A=\left[\begin{array}{llll}a_{11} & a_{12} & a_{13} \\ a_{21} & a_{22} & a_{23} \\ a_{31} & a_{32} & a_{33}\end{array}\right]$, then:

$$
|A|=a_{i 1} A_{i 1}+a_{i 2} A_{i 2}+a_{i 3} A_{i 3} \quad \text { for } i=1,2,3
$$

or $|A|=a_{1 j} A_{1 j}+a_{2 j} A_{2 j}+a_{3 j} A_{3 j}$ for $j=1,2,3$
For example, for $i=1, j=1$ and $j=2$, we have

$$
\begin{aligned}
& |A|=a_{11} A_{11}+a_{12} A_{12}+a_{13} A_{13} \\
& \text { or }|A|=a_{11} A_{11}+a_{21} A_{21}+a_{31} A_{31} \\
& \text { or }|A|=a_{12} A_{12}+a_{22} A_{22}+a_{32} A_{32}
\end{aligned}
$$

(iii) can be written as: $|A|=a_{12}(-1)^{1 / 2} M_{12}+a_{22}(-1)^{2 / 2} M_{22}+a_{32}(-1)^{3 / 2} M_{32}$

i.e., $|A|=-a_{12} M_{12}+a_{23} M_{23}-a_{32} M_{32}$
Similarly (i) can be written as $|A|=a_{11} M_{11}-a_{12} M_{12}+a_{13} M_{13}$
Putting the values of $M_{11}, M_{12}$ and $M_{13}$ in (v), we obtain

$$
\begin{aligned}
& |A|=\left.a_{11}\right|_{a_{32}} ^{a_{23}}\left.a_{33}\right|_{-a_{12}}\left|\begin{array}{ll}
a_{21} & a_{23} \\
a_{31} & a_{33}
\end{array}\right|+a_{13}\left|\begin{array}{ll}
a_{21} & a_{23} \\
a_{31} & a_{32}
\end{array}\right| \\
& \text { or }|A|=a_{11}\left(a_{22} a_{33}-a_{23} a_{32}\right)-a_{12}\left(a_{21} a_{33}-a_{22} a_{31}\right)+a_{13}\left(a_{21} a_{32}-a_{22} a_{31}\right) \\
& \text { or }|A|=a_{11} a_{22} a_{33}+a_{12} a_{23} a_{31}+a_{13} a_{21} a_{32}-a_{11} a_{23} a_{32}-a_{12} a_{21} a_{33}-a_{13} a_{22} a_{31}
\end{aligned}
$$

Equation (vii) is the required expansion of determinant of square matrix of order 3.
Example 4 Evaluate the determinant if $A=\left[\begin{array}{rrr}1 & -2 & 3 \\ -2 & 3 & 1 \\ 4 & -3 & 2\end{array}\right]$.

Solution $|A|=\left|\begin{array}{rrr}1 & -2 & 3 \\ -2 & 3 & 1 \\ 4 & -3 & 2\end{array}\right|$
using

$$
\begin{aligned}
|A| & =a_{11} M_{11}-a_{12} M_{12}+a_{13} M_{13}, \text { we get } \\
|A| & =1\left|\begin{array}{rr}
3 & 1 \\
-3 & 2
\end{array}\right|-(-2)\left|\begin{array}{rr}
-2 & 3 \\
4 & 2
\end{array}\right|+3\left|\begin{array}{rr}
-2 & 3 \\
4 & -3
\end{array}\right| \\
& =1(6-1(-3)]+2[(-2)(2)-(1)(4)]+3[(-2)(-3)-12] \\
& =(6+3)+2(-4-4)+3(6-12)=9-16-18=-25
\end{aligned}
$$

Example 5 Find the cofactors $A_{12}, A_{22}$ and $A_{32}$ of $A=\left[\begin{array}{rrr}1 & -2 & 3 \\ -2 & 3 & 1 \\ 4 & -3 & 2\end{array}\right]$ and find $|A|$.
Solution We first find $M_{12}, M_{22}$ and $M_{32}$,

$$
\begin{aligned}
& M_{12}=\left|\begin{array}{rr}
-2 & 1 \\
4 & 2
\end{array}\right|=-4-4=-8 ; M_{22}=\left|\begin{array}{ll}
1 & 3 \\
4 & 2
\end{array}\right|=2-12=-10 \\
& \text { and } \quad M_{32}=\left|\begin{array}{rr}
1 & 3 \\
-2 & 1
\end{array}\right|=1-(-6)=7 \\
& \text { Thus } \quad A_{12}=(-1)^{1+2} M_{12}=(-1)(-8)=8 ; \quad A_{22}=(-1)^{2+2} M_{22}=1(-10)=-10 \\
& A_{32}=(-1)^{3+2} M_{32}=(-1)(7)=-7 \\
& \text { and } \quad|A|=a_{12} A_{12}+a_{22} A_{22}+a_{33} A_{33}=(-2) 8+3(-10)+(-3)(-7) \\
& \quad=-16-30+21=-25
\end{aligned}
$$

# 4.4.3 Properties of Determinants 

i. For a square matrix $A,|A|=|A|$
ii. If in a square matrix $A$, two rows or two columns are interchanged, the determinant of the resulting matrix is $-|A|$.
iii. If a square matrix $A$ has two identical rows or two identical columns, then $|A|=0$.
iv. If all the entries of a row (or a column) of a square matrix $A$ are zero, then $|A|=0$.
v. If the entries of a row (or a column) in a square matrix $A$ are multiplied by a number $k \in R$, then the determinant of the resulting matrix is $k|A|$.
vi. If each entry of a row (or a column) of a square matrix consists of two terms, then its determinant can be written as the sum of two determinants, i.e., if

$$
\begin{aligned}
B & =\left[\begin{array}{lll}
a_{11}+b_{11} & a_{12} & a_{13} \\
a_{21}+b_{21} & a_{22} & a_{23} \\
a_{31}+b_{31} & a_{32} & a_{33}
\end{array}\right], \text { then } \\
|B| & =\left|\begin{array}{lll}
a_{11}+b_{11} & a_{12} & a_{13} \\
a_{21}+b_{21} & a_{22} & a_{23} \\
a_{31}+b_{31} & a_{32} & a_{33}
\end{array}\right|=\left|\begin{array}{llll}
a_{11} & a_{12} & a_{13} \\
a_{21} & a_{22} & a_{23} \\
a_{31} & a_{32} & a_{33}
\end{array}\right|+\left|\begin{array}{llll}
b_{11} & a_{12} & a_{13} \\
b_{21} & a_{22} & a_{23} \\
b_{31} & a_{32} & a_{33}
\end{array}\right|
\end{aligned}
$$

vii. If any row (column) of a determinant is multiplied by a non-zero number $k$ and the result is added to the corresponding entries of another row (column), the value of the determinant does not change.
viii. If a matrix is in triangular form, then the value of its determinant is the product of the entries on its main diagonal.

## Note We shall define triangular matrices on page 61.

Example 6 Without expansion, show that $\left|\begin{array}{lll}x & a+x & b+c \\ x & b+x & c+a \\ x & c+x & a+b\end{array}\right|$
Solution Adding the entries of $C_{3}$ to the corresponding entries of $C_{2}$.
L.H.S $=\left|\begin{array}{lll}x & a+b+c+x & b+c \\ x & a+b+c+x & c+a \\ x & a+b+c+x & a+b\end{array}\right|$

$$
\begin{aligned}
& =x(a+b+c+x)\left|\begin{array}{lll}
1 & 1 & b+c \\
1 & 1 & c+a \\
1 & 1 & a+b
\end{array}\right| \quad\left(\begin{array}{lll}
\text { by taking } x \text { common from } C_{1} \text { and } \\
(a+b+c+x) \text { common from } C_{2}
\end{array}\right) \\
& =x(a+b+c+x) \cdot 0 \quad\left(\because C_{1} \text { and } C_{2} \text { are identical }\right) \\
& =0=\text { R.H.S }
\end{aligned}
$$

# 4.5 Adjoint and Inverse of a Square Matrix 

Let $A=\left[\begin{array}{lll}a_{11} & a_{12} & a_{13} \\ a_{21} & a_{22} & a_{23} \\ a_{31} & a_{32} & a_{33}\end{array}\right]$, then the matrix of co-factors of $A=\left[\begin{array}{lll}A_{11} & A_{12} & A_{13} \\ A_{21} & A_{22} & A_{23} \\ A_{31} & A_{32} & A_{33}\end{array}\right]$,
and adj $A=\left[\begin{array}{lll}A_{11} & A_{21} & A_{31} \\ A_{12} & A_{22} & A_{32} \\ A_{13} & A_{23} & A_{33}\end{array}\right]$
Inverse of a Square Matrix of Order $n \geq 3$ : Let $A$ be a non singular $(|A| \neq 0)$ square matrix of order $n$. If there exists a matrix $B$ such that $A B=B A=I_{n}$, then $B$ is called the multiplicative inverse of $A$ and is denoted by $A^{-1}$. It is obvious that the order of $A^{-1}$ is $n \times n$.
Thus, $A A^{-1}=I_{n}$ and $A^{-1} A=I_{n}$.
If $A$ is non singular matrix then

$$
A^{-1}=\frac{1}{|A|} \operatorname{adj} A
$$

Example 7 Find $A^{-1}$ if $A=\left[\begin{array}{ccc}1 & 0 & 2 \\ 0 & 2 & 1 \\ 1 & -1 & 1\end{array}\right]$.
Solution We first find the cofactors of the elements of $A$.
$A_{11}=(-1)^{1+1}\left|\begin{array}{cc}2 & 1 \\ -1 & 1\end{array}\right|=1 \cdot(2+1)=3, \quad A_{12}=(-1)^{1+2}\left|\begin{array}{ll}0 & 1 \\ 1 & 1\end{array}\right|=(-1)(-1)=1$
$A_{13}=(-1)^{1+3}\left|\begin{array}{ll}0 & 2 \\ 1 & -1\end{array}\right|=1 \cdot(0-2)=-2, \quad A_{21}=(-1)^{2+1}\left|\begin{array}{cc}0 & 2 \\ -1 & 1\end{array}\right|=(-1)(0+2)=-2$
$A_{22}=(-1)^{2+2}\left|\begin{array}{ll}1 & 2 \\ 1 & 1\end{array}\right|=1 \cdot(1-2)=-1, \quad A_{23}=(-1)^{2+3}\left|\begin{array}{cc}1 & 0 \\ 1 & -1\end{array}\right|=(-1)(-1-0)=1$
$A_{31}=(-1)^{3+1}\left|\begin{array}{ll}0 & 2 \\ 2 & 1\end{array}\right|=1 \cdot(0-4)=-4, \quad A_{32}=(-1)^{3+2}\left|\begin{array}{ll}1 & 2 \\ 0 & 1\end{array}\right|=(-1)(1-0)=-1$
$A_{33}=(-1)^{3+3}\left|\begin{array}{ll}1 & 0 \\ 0 & 2\end{array}\right|=1 \cdot(2-0)=2$

Thus

$$
\left[A_{i j}\right]_{3 \times 3}=\left[\begin{array}{lll}
A_{11} & A_{12} & A_{13} \\
A_{21} & A_{22} & A_{23} \\
A_{31} & A_{32} & A_{33}
\end{array}\right]=\left[\begin{array}{rrr}
3 & 1 & -2 \\
-2 & -1 & 1 \\
-4 & -1 & 2
\end{array}\right]
$$

and adj $A=\left[A_{i j}\right]_{3 \times 3}=\left[\begin{array}{rrr}3 & -2 & -4 \\ 1 & -1 & -1 \\ -2 & 1 & 2\end{array}\right] \quad\left(\because A_{i j}^{\prime}=A_{j i}\right.$ for $\left.i, j=1,2,3\right)$
Since

$$
\begin{aligned}
|A| & =a_{11} A_{11}+a_{12} A_{12}+a_{13} A_{13} \\
& =1(3)+0(1)+2(-2) \\
& =3+0-4=-1
\end{aligned}
$$

So

$$
A^{-1}=\frac{1}{|A|} \operatorname{adj} A=\frac{1}{-1}\left[\begin{array}{rrr}
3 & -2 & -4 \\
1 & -1 & -1 \\
-2 & 1 & 2
\end{array}\right]=\left[\begin{array}{rrr}
-3 & 2 & 4 \\
-1 & 1 & 1 \\
2 & -1 & -2
\end{array}\right]
$$

# EXERCISE 4.2 

1. Evaluate the following determinants
(i) $\left|\begin{array}{rrr}1 & -2 & -4 \\ 3 & -1 & -3 \\ -2 & 3 & 2\end{array}\right|$
(ii) $\left|\begin{array}{rrr}a+b & a-b & a \\ a & a+b & a-b \\ a-b & a & a+b\end{array}\right|$
(iii) $\left|\begin{array}{lll}2 x & x & x \\ y & 2 y & y \\ z & z & 2 z\end{array}\right|$
2. Without expansion, alow that:
(i) $\left|\begin{array}{lll}7 & 8 & 9 \\ 5 & 6 & 7 \\ 2 & 3 & 4\end{array}\right|=0$
(ii) $\left|\begin{array}{lll}5 & 6 & -1 \\ 2 & 2 & 0 \\ 2 & -8 & 10\end{array}\right|=0$
(iii) $\left|\begin{array}{ccc}-a & 0 & b \\ 0 & a & -c \\ c & -b & 0\end{array}\right|=0$
(iv) $\left|\begin{array}{lllll}l & m+n & 1 & =0 & (v) \\ m & n+l & 1 & =0 & (v) \\ n & l+m & 1 & & 3\end{array}\right| \begin{aligned} & \left.\begin{array}{lll}2 & 1 & 3 x \\ 2 & 3 & 9 x \\ 3 & 5 & 15 x\end{array}\right|=0 \quad \begin{array}{lllll}\text { (vi) } & \begin{array}{lllll}b c & a & a^{2} \\ c a & b & b^{2} \\ a b & c & c^{2}\end{array}\end{array} & =\left.\begin{array}{lllll}1 & a^{2} & a^{3} \\ 1 & b^{2} & b^{3} \\ 1 & c^{2} & c^{3}\end{array}\right.\right.\end{aligned}$
3. Using properties of determinants, show that:
(i) $\left|\begin{array}{lllll}3 & 5 & 0 & & 3 & 1 & 0 \\ 5 & 25 & 10 & =25 & 1 & 1 & 2 \\ 7 & 25 & 1 & & 7 & 5 & 1\end{array}\right|$
(ii) $\left|\begin{array}{ccc}a+x & a & a \\ a & a+x & a \\ a & a & a+x\end{array}\right|=x^{3}(3 a+x)$

(iii) $\left|\begin{array}{lll}1 & x & y z \\ 1 & y & z x \\ 1 & z & x y\end{array}\right|=\left|\begin{array}{ccc}1 & x & x^{2} \\ 1 & y & y^{2} \\ 1 & z & z^{2}\end{array}\right|$
(iv) $\left|\begin{array}{ccc}1 & x & x^{2} \\ 1 & y & y^{2} \\ 1 & z & z^{2}\end{array}\right|=(x-y)(y-z)(z-x)$
(v) $\left|\begin{array}{ccc}1 & 1 & 1 \\ a+1 & b+1 & c+1 \\ (a+1)^{2} & (b+1)^{2} & (c+1)^{2}\end{array}\right|=(a-b)(b-c)(c-a)$
(vi) $\left|\begin{array}{ccc}a^{2}+b^{2} & c^{2} & c^{2} \\ a^{2} & b^{2}+c^{2} & a^{2} \\ b^{2} & b^{2} & c^{2}+a^{2}\end{array}\right|=4 a^{2} b^{2} c^{2}$
(vii) $\left|\begin{array}{ccc}a & b & c \\ b+c & c+a & a+b \\ a+b & b+c & c+a\end{array}\right|=a^{3}+b^{3}+c^{3}-3 a b c$
(viii) $\left|\begin{array}{ccc}a+t & a & a \\ b & b+t & b \\ c & c & c+t\end{array}\right|=t^{2}(a+b+c+t)$
(ix) $\left|\begin{array}{ccc}a-b-c & 2 a & 2 a \\ 2 b & b-c-a & 2 b \\ 2 c & 2 c & c-a-b\end{array}\right|=(a+b+c)^{3}$
(x) $\left|\begin{array}{ccc}y+z & z+x & x+y \\ x & y & z \\ x^{2} & y^{2} & z^{2}\end{array}\right|=(x+y+z)(x-y)(y-z)(z-x)$
(xi) $\left|\begin{array}{ccc}1 & 1 & 1 \\ a^{2}+1 & b^{2}+1 & c^{2}+1 \\ a^{2}+a & b^{2}+b & c^{3}+c\end{array}\right|=(a-b)(b-c)(c-a)(a b+b c+c a-1)$
(xii) $\left|\begin{array}{ccc}1+a & 1 & 1 \\ 1 & 1+b & 1 \\ 1 & 1 & 1+c\end{array}\right|=a b c+a b+b c+c a \quad$ (xiii) $\left|\begin{array}{ccc}1 & a & a^{2}-b c \\ 1 & b & b^{2}-c a \\ 1 & c & c^{2}-a b\end{array}\right|=0$

(a) Matrices and Determinants
(2) Mathemathes (1)
$(x i v)$ | $2 x+3$ | $x+2$ | $x+a$ |
| :-- | :-- | :-- |
| $2 x+5$ | $x+3$ | $x+b=0$, where $2 b=a+c$ |
| $2 x+7$ | $x+4$ | $x+c \mid$ |

(xv) | $a$ | $b$ | $c$ |
| :-- | :-- | :-- |
| $c$ | $a$ | $b \mid=(a+b+c)\left(a+b \omega+c \omega^{2}\right)\left(a+b \omega^{2}+c \omega\right)$, where $\omega$ is an |
| $b$ | $c$ | $a \mid$ |

imaginary cube root of unity.
4. If $A=\left[\begin{array}{ccc}1 & 2 & -3 \\ 0 & -5 & 0 \\ -2 & -2 & 7\end{array}\right]$ and $B=\left[\begin{array}{ccc}-5 & -2 & 5 \\ -3 & -1 & 4 \\ -2 & -1 & 2\end{array}\right]$, then find:
(i) $A_{13}, A_{23}, A_{33}$ and $|A|$
(ii) $B_{31}, B_{32}, B_{33}$ and $|B|$
5. Find the values of $x$ if:
(i) $\left|\begin{array}{ccc}2 & 1 & x \\ -1 & -4 & -3 \\ x & 1 & 0\end{array}\right|=5$
(ii) $\left|\begin{array}{ccc}1 & x-1 & 3 \\ -1 & x+1 & 2 \\ 2 & -3 & x\end{array}\right|=9$
(iii) $\left|\begin{array}{ccc}1 & 1 & 1 \\ 2 & x & 2 \\ 3 & 6 & x\end{array}\right|=0$
6. Find $\left|A A^{\prime}\right|$ and $|A A|$ if:
(i) $A=\left[\begin{array}{lll}-3 & 2 & -1 \\ 2 & 1 & 3\end{array}\right]$
(ii) $A=\left[\begin{array}{ll}3 & 1 \\ 2 & 2 \\ 1 & 3\end{array}\right]$
7. If $A$ is a square matrix of order 3 , then show that $|k A|=k^{3}|A|$.
8. Find the values of $A$ if $A$ and $B$ are singular.

$$
A=\left[\begin{array}{lll}
4 & 2 & 3 \\
7 & 1 & 6 \\
2 & 3 & 1
\end{array}\right], \quad B=\left[\begin{array}{lll}
-2 & 4 & 5 \\
1 & -2 & 1 \\
2 & 1 & 0
\end{array}\right]
$$

9. Find the inverse of $A=\left[\begin{array}{lll}1 & 2 & 1 \\ -5 & 0 & 4 \\ 5 & 4 & 0\end{array}\right]$ and show that $A^{-1} A=I$,
10. Verify that $(A B)^{\prime}=B^{\prime} A^{\prime}$ if:
(i) $A=\left[\begin{array}{lll}1 & -1 & 2 \\ 0 & -3 & 1\end{array}\right]$ and $B=\left[\begin{array}{cc}1 & 1 \\ -3 & -2 \\ 0 & 1\end{array}\right]$
(ii) $A=\left[\begin{array}{ll}1 & 2 \\ 1 & 4 \\ 2 & 1\end{array}\right]$ and $B=\left[\begin{array}{cc}1 & -3 \\ -2 & 1\end{array}\right]$

# 4.6 Elementary Row Operations on a Matrix 

Usually, a given system of linear equations is reduced to a simple equivalent system by applying elementary operations which are stated as below:
(i) Interchanging two equations.
(ii) Multiplying an equation by a non-zero number.
(iii) Adding a multiple of one equation to another equation.

Corresponding to these three elementary operations, the following elementary row operations are applied to matrices to obtain equivalent matrices:
(i) Interchanging two rows
(ii) Multiplying a row by a non-zero number
(iii) Adding a multiple of one row to another row

Note Matrices $A$ and $B$ are equivalent if $B$ can
Notations that are used to represent row operations for (i) to (iii) are given below:
in turn a finite number of row operations on $A$.

- Interchanging $R_{i}$ and $R_{j}$ is expressed as $R_{i} \leftrightarrow R_{j}$.
- $k$ times $R_{i}$ is denoted by $k R_{i} \rightarrow R_{i}^{\prime}$.
- Adding $k$ times $R_{j}$ to $R_{i}$ is expressed as $R_{i}+k R_{j} \rightarrow R_{i}^{\prime}$
( $R_{i}^{\prime}$ is the new row obtained after applying the row operation).
For equivalent matrices $A$ and $B$, we write $A \underline{B} B$.
If $A \underline{B} B$ then $B \underline{B} A$
Upper Triangular Matrix: A square matrix $A=\left[a_{i j}\right]$ is called an upper triangular matrix if all elements below the principal diagonal are zero, that is,

$$
a_{i j}=0 \text { for all } i>j
$$

Lower Triangulur Matrix: A square matrix $A=\left[a_{i j}\right]$ is said to be lower triangular matrix if all elements above the principal diagonal are zero, that is,

$$
a_{i j} \geqslant 0 \text { for all } i<j
$$

Triangular Matrix: A square matrix $A$ is named as triangular matrix whether it is upper triangular or lower triangular. For example, the matrices

$$
\left[\begin{array}{lll}
1 & 2 & 3 \\
0 & 1 & 4 \\
0 & 0 & 6
\end{array}\right] \text { and }\left[\begin{array}{llll}
1 & 0 & 0 & 0 \\
3 & 2 & 0 & 0 \\
4 & 1 & 5 & 0 \\
-1 & 2 & 3 & 1
\end{array}\right] \text { are triangular matrices of order } 3 \text { and } 4 \text { respectively. }
$$

The first matrix is upper triangular while the second is lower triangular.

## Remember!

Diagonal matrices are both upper triangular and lower triangular.

# 4.7 Echelon and Reduced Echelon Forms of Matrices 

In any non-zero row of a matrix, the first non-zero entry is called the leading entry of that row.

## Echelon Form of a Matrix

An $m \times n$ matrix $A$ is called in echelon form if:
(i) The number of zeros before the leading entry is greater than the number zeros in the preceding row.
(ii) Every non-zero row in $A$ precedes every zero row (if any).
(iii) The first non-zero entry (or leading entry) in each row is 1 .

The matrices $\left[\begin{array}{llll}0 & 1 & -2 & 4 \\ 0 & 0 & 1 & 2 \\ 0 & 0 & 0 & 0\end{array}\right]$ and $\left[\begin{array}{llll}1 & 2 & -3 & 4 \\ 0 & 0 & 1 & 2 \\ 0 & 0 & 0 & 1\end{array}\right]$ are in echelon form

Reduced Echelon Form of a Matrix: An $m \times n$ matrix $A$ is said to be in reduced (row) echelon form if the first non-zero entry (or leading entry) in $R_{i}$ lies in $C_{j}$, then all other entries of $C_{j}$ are zero.

The matrices $\left[\begin{array}{llll}0 & 1 & 0 & 4 \\ 0 & 0 & 1 & 2 \\ 0 & 0 & 0 & 0\end{array}\right]$ and $\left[\begin{array}{llll}1 & 2 & 0 & 0 \\ 0 & 0 & 1 & 0 \\ 0 & 0 & 0 & 1\end{array}\right]$ are in (row) reduced echelon form.

Example 3 Reduce $\left[\begin{array}{llll}2 & 3 & -1 & 9 \\ 1 & -1 & 2 & -3 \\ 3 & 1 & 3 & 2\end{array}\right]$ to (row) echelon and reduced (row) echelon form.

Solution $\left[\begin{array}{llll}2 & 3 & -1 & 9 \\ 1 & -1 & 2 & -3 \\ 3 & 1 & 3 & 2\end{array}\right], \notin\left[\begin{array}{llll}1 & -1 & 2 & -3 \\ 2 & 3 & -1 & 9 \\ 3 & 1 & 3 & 2\end{array}\right]$ By $R_{1} \leftrightarrow R_{2}$

$$
\begin{aligned}
& \text { B }\left[\begin{array}{llll}
1 & -1 & 2 & -3 \\
0 & 5 & -5 & 15 \\
0 & 4 & -3 & 11
\end{array}\right] \begin{array}{l}
\text { By } R_{2}+(-2) R_{1} \rightarrow R_{2}^{\prime} \\
\text { and } R_{3}+(-3) R_{1} \rightarrow R_{1}^{\prime}
\end{array} \notin\left[\begin{array}{llll}
1 & -1 & 2 & -3 \\
0 & 1 & -1 & 3 \\
0 & 4 & -3 & 11
\end{array}\right] \frac{1}{2} R_{2} \rightarrow R_{2}^{\prime}
\end{aligned}
$$

$$
\begin{aligned}
& \text { 定 }\left[\begin{array}{llll}
1 & -1 & 2 & -3 \\
0 & 1 & -1 & 3 \\
0 & 0 & 1 & -1
\end{array}\right] R_{2}+(-4) R_{2} \rightarrow R_{2}^{\prime} \quad \notin\left[\begin{array}{llll}
1 & 0 & 1 & 0 \\
0 & 1 & -1 & 3 \\
0 & 0 & 1 & -1
\end{array}\right] R_{1}+1 . R_{2} \rightarrow R_{1}^{\prime}
\end{aligned}
$$

$R\left[\begin{array}{llll}1 & 0 & 0 & 1 \\ 0 & 1 & 0 & 2 \\ 0 & 0 & 1 & -1\end{array}\right]$
Thus $\left[\begin{array}{llll}1 & -1 & 2 & -3 \\ 0 & 1 & -1 & 3 \\ 0 & 0 & 1 & -1\end{array}\right]$ and $\left[\begin{array}{llll}1 & 0 & 0 & 1 \\ 0 & 1 & 0 & 2 \\ 0 & 0 & 1 & -1\end{array}\right]$ are (row) echelon and reduced (row)
echelon forms of the given matrix respectively.
Inverse of a Matriz: Let $A$ be a non-singular matrix. If the application of elementary row operations on $A: I$ in succession reduces $A$ to $I$, then the resulting matrix is $I: A^{-1}$.

Example 9 Find the inverse of the matrix $A=\left[\begin{array}{llll}2 & 5 & -1 \\ 3 & 4 & 2 \\ 1 & 2 & -2\end{array}\right]$
Solution $|A|=\left|\begin{array}{lll}2 & 5 & -1 \\ 3 & 4 & 2 \\ 1 & 2 & -2\end{array}\right|=2(-8-4)-5(-6-2)-1(6-4)=-24+40-2=40-26=14$
As $|A| \neq 0$, so $A$ is non-singular.
Appending $I_{3}$ on the right of the matrix $A$, we have $\left[\begin{array}{llllll}2 & 5 & -1 & \vdots & 1 & 0 & 0 \\ 3 & 4 & 2 & \vdots & 0 & 1 & 0 \\ 1 & 2 & -2 & \vdots & 0 & 0 & 1\end{array}\right]$
Interchanging $R_{1}$ and $R_{2}$ we get,

$$
\left[\begin{array}{llllll}
1 & 2 & -2 & \vdots & 0 & 0 & 1 \\
3 & 4 & 2 & \vdots & 0 & 1 & 0 \\
2 & 5 & -1 & \vdots & 1 & 0 & 0
\end{array}\right] R\left[\begin{array}{llllll}
1 & 2 & -2 & \vdots & 0 & 0 & 1 \\
0 & -2 & 8 & \vdots & 0 & 1 & -3 \\
0 & 1 & 3 & \vdots & 1 & 0 & -2
\end{array}\right] \begin{gathered}
\text { By } R_{3}+(-3) R_{1} \rightarrow R_{2}^{\prime} \\
\text { and } R_{3}+(-2) R_{1} \rightarrow R_{2}^{\prime}
\end{gathered}
$$

By $-\frac{1}{2} R_{2} \rightarrow R_{2}^{\prime}$, we get

$$
\left[\begin{array}{cccccc}
1 & 2 & -2 & \vdots & 0 & 0 & 1 \\
0 & 1 & -4 & \vdots & 0 & -\frac{1}{2} & \frac{3}{2} \\
0 & 1 & 3 & \vdots & 1 & 0 & -2
\end{array}\right] R\left[\begin{array}{cccccc}
1 & 0 & 6 & \vdots & 0 & 1 & -2 \\
0 & 1 & -4 & \vdots & 0 & -\frac{1}{2} & \frac{3}{2} \\
0 & 0 & 7 & \vdots & 1 & \frac{1}{2} & -\frac{7}{2}
\end{array}\right] \begin{gathered}
\text { By } R_{1}+(-1) R_{2} \rightarrow R_{2}^{\prime} \\
\text { and } R_{1}+(-2) R_{2} \rightarrow R_{1}^{\prime}
\end{gathered}
$$

By $\frac{1}{7} R_{3} \rightarrow R_{3}^{\prime}$, we have

$$
\left[\begin{array}{ccccc}
1 & 0 & 6 & \vdots & 0 & 1 & -2 \\
0 & 1 & -4 & \vdots & 0 & -\frac{1}{2} & \frac{3}{2} \\
0 & 0 & 1 & \vdots & \frac{1}{7} & \frac{1}{14} & -\frac{1}{2}
\end{array}\right] \begin{aligned}
& \text { I } \\
& \text { By } R_{1}+(-6) R_{3} \rightarrow R_{1}^{\prime} \\
& \text { and } R_{3}+4 R_{3} \rightarrow R_{2}^{\prime}
\end{aligned}
$$

Thus, the inverse of $A$ is $\left[\begin{array}{rrr}-\frac{6}{7} & \frac{4}{7} & 1 \\ \frac{4}{7} & -\frac{3}{14} & -\frac{1}{2} \\ \frac{1}{7} & \frac{1}{14} & -\frac{1}{2}\end{array}\right]$

Rank of a Matrix: Let $A$ be a non-zero matrix. If $r$ is the number of non-zero rows when it is reduced to the echelon form, then $r$ is called the rank of the matrix $A$.

Example 10 Find the rank of the matrix

$$
\left[\begin{array}{cccc}
1 & -1 & 2 & -3 \\
2 & 0 & 7 & -7 \\
3 & 1 & 12 & -11
\end{array}\right]
$$

Solution $\left[\begin{array}{cccc}1 & -1 & 2 & -3 \\ 2 & 0 & 7 & -7 \\ 3 & 1 & 12 & -11\end{array}\right] \quad\left[\begin{array}{cccc}1 & -1 & 2 & -3 \\ 0 & 2 & 3 & -1 \\ 0 & 4 & 6 & -2\end{array}\right] \quad$ By $R_{2}+(-2) R_{1} \rightarrow R_{2}^{\prime}$ and $R_{3}+(-3) R_{1} \rightarrow R_{3}^{\prime}$

$$
\left[\begin{array}{cccc}
1 & -1 & 2 & -3 \\
0 & 1 & \frac{3}{2} & \frac{1}{2} \\
0 & 4 & \frac{6}{6} & -2
\end{array}\right] \text { By } \frac{1}{2} R_{2} \rightarrow R_{2}^{\prime} \quad\left[\begin{array}{cccc}
1 & -1 & 2 & -3 \\
0 & 1 & \frac{3}{2} & -\frac{1}{2} \\
0 & 0 & 0 & 0
\end{array}\right] \text { By } R_{3}+(-4) R_{2} \rightarrow R_{3}^{\prime}
$$

As the number of non-zero rows is 2 when the given matrix is reduced to echelon form, therefore, the rank of the given matrix is 2 .

# 4.8 System of Non-Homogeneous Linear Equations 

Three linear equations in three variables such as:

$$
\left.\begin{array}{rl}
a_{1} x+b_{1} y+c_{1} z & =d_{1} \\
a_{2} x+b_{2} y+c_{2} z & =d_{2} \\
a_{3} x+b_{3} y+c_{3} z & =d_{3}
\end{array}\right\}
$$

is called a system of non-homogeneous linear equations in the three variables $x, y$ and $z$, if constant terms $d_{1}, d_{2}$ and $d_{3}$ are not all zero.

Consistent: A system of linear equations is said to be consistent if the system has a unique solution or it has infinitely many solutions.
Inconsistent: A system of linear equations is said to be inconsistent if the system has no solution.
Now we will solve the system of non-homogeneous linear equations with the help of the following methods:
(i) Using reduced echelon form
(ii) Using matrix inversion method
(iii) Using Cramer's rule

# 4.8.1 Reduced Echelon Form 

There are following steps to solve a system of non-homogeneous linear equations (i):
(i) Convert to augmented matrix
i.e.

$$
\left[\begin{array}{lll}
a_{1} & b_{1} & c_{1} & d_{1} \\
a_{2} & b_{2} & c_{2} & d_{2} \\
a_{3} & b_{3} & c_{3} & d_{3}
\end{array}\right]
$$

(ii) Convert to reduced echelon form
(iii) Solve by back substitution

Example 11 Solve the following and explain a consistent and inconsistent system:
(i) $2 x+5 y-z=5$
(ii) $x+y+2 z=1$
(iii) $x-y+2 z=1$
$3 x+4 y+2 z=11$
$2 x-y+7 z=11$
$2 x-6 y+5 z=7$
$x+2 y-2 z=-3$
$3 x+5 y+4 z=-3$
$3 x+5 y+4 z=-3$

Solution (i) The augmented matrix of the given system is $\left[\begin{array}{lllll}2 & 5 & -1 & \vdots & 5 \\ 3 & 4 & 2 & \vdots & 11 \\ 1 & 2 & -2 & \vdots & -3\end{array}\right]$
We apply the elementary row operations to the above matrix to reduce it to the equivalent reduced (row) echelon form, that is,

$$
\left[\begin{array}{lllll}
2 & 5 & -1 & \vdots & 5 \\
3 & 4 & 2 & \vdots & 11 \\
1 & 2 & -2 & \vdots & -3
\end{array}\right] \quad\left[\begin{array}{lllll}
1 & 2 & -2 & \vdots & -3 \\
3 & 4 & 2 & \vdots & 11 \\
2 & 5 & -1 & \vdots & 5
\end{array}\right] \quad \text { By } R_{1} \leftrightarrow R_{3}
$$

$\left[\begin{array}{cccccc}1 & 2 & -2 & \vdots & -3 \\ 0 & -2 & 8 & \vdots & 20 \\ 2 & 5 & -1 & \vdots & 5\end{array}\right]$ By $R_{2}+(-3) R_{1} \rightarrow R_{2}^{\prime} \underline{R}\left[\begin{array}{cccccc}1 & 2 & -2 & \vdots & -3 \\ 0 & -2 & 8 & \vdots & 20 \\ 0 & 1 & 3 & \vdots & 11\end{array}\right]$ By $R_{3}+(-2) R_{1} \rightarrow R_{3}^{\prime}$

By $-\frac{1}{2} R_{2} \rightarrow R_{2}^{\prime}$, we get
$\underline{R}\left[\begin{array}{ccccc:c:}1 & 2 & -2 & \vdots & -3 \\ 0 & 1 & -4 & \vdots & -10 \\ 0 & 1 & 3 & \vdots & 11\end{array}\right] \underline{R}\left[\begin{array}{ccccc:c:}1 & 0 & 6 & \vdots & 17 \\ 0 & 1 & -4 & \vdots & -10 \\ 0 & 0 & 7 & \vdots & 21\end{array}\right]$ and $R_{1}+(-2) R_{2} \rightarrow R_{1}^{\prime}$ and $R_{3}+(-1) R_{2} \rightarrow R_{3}^{\prime}$
$\underline{R}\left[\begin{array}{ccccc:c:}1 & 0 & 6 & \vdots & 17 \\ 0 & 1 & -4 & \vdots & -10 \\ 0 & 0 & 1 & \vdots & 3\end{array}\right]$ By $\frac{1}{7} R_{3} \rightarrow R_{3}^{\prime} \quad \underline{R}\left[\begin{array}{ccccc:c:}1 & 0 & 0 & \vdots & -1 \\ 0 & 1 & 0 & \vdots & 2 \\ 0 & 0 & 1 & \vdots & 3\end{array}\right]$ and $R_{2}+4 R_{3} \rightarrow R_{2}^{\prime}$ Thus, the solution is $x=-1, y=2$ and $z=3$, therefore the given system of linear equations has unique solution and it is consistent.
(ii) The augmented matrix of the given system is $\left[\begin{array}{ccccc:c:}1 & 1 & 2 & \vdots & 1 \\ 2 & -1 & 7 & \vdots & 11 \\ 3 & 5 & 4 & \vdots & -3\end{array}\right]$
$\left[\begin{array}{ccccc:c:}1 & 1 & 2 & \vdots & 1 \\ 2 & -1 & 7 & \vdots & 11 \\ 3 & 5 & 4 & \vdots & -3\end{array}\right] \quad \underline{R}\left[\begin{array}{ccccc:c:}1 & 1 & 2 & \vdots & 1 \\ 0 & -3 & 3 & \vdots & 9 \\ 0 & 2 & -2 & \vdots & -6\end{array}\right]$ Adding $(-2) R_{1}$ to $R_{2}$ and $(-3) R_{1}$ to $R_{3}$.
We get, $\underline{R}\left[\begin{array}{ccccc:c:}1 & 1 & 2 & \vdots & 1 \\ 0 & 1 & -1 & \vdots & -3 \\ 0 & 2 & -2 & \vdots & -6\end{array}\right]$ By $-\frac{1}{3} R_{2} \rightarrow R_{2}^{\prime} \quad \underline{R}\left[\begin{array}{ccccc:c:}1 & 0 & 3 & \vdots & 4 \\ 0 & 1 & -1 & \vdots & -3 \\ 0 & 0 & 0 & \vdots & 0\end{array}\right] \quad \begin{aligned} & \text { By } R_{1}+(-1) R_{2} \rightarrow R_{1}^{\prime} \\ & \text { and } R_{3}+(-2) R_{2} \rightarrow R_{3}^{\prime}\end{aligned}$
The given system is reduced to equivalent system

$$
\begin{aligned}
x+3 z & =4 \\
y-z & =-3 \\
0 z & =0
\end{aligned}
$$

The equation $0 z=0$ is satisfied by any value of $z$.
From the first and second equations, we get

$$
\begin{aligned}
& x=-3 z+4 \\
& \text { and } \quad y=z-3
\end{aligned}
$$

As $z$ is arbitrary, so we can find infinitely many values of $x$ and $y$ from equations (a) and (b) or the given system, is satisfied by $x=4-3 t, y=t-3$ and $z=t$ for any real value of $t$.
Thus, the given system has infinitely many solutions and it is consistent.
(iii) The augmented matrix of the system is $\left[\begin{array}{ccccc:c:}1 & -1 & 2 & \vdots & 1 \\ 2 & -6 & 5 & \vdots & 7 \\ 3 & 5 & 4 & \vdots & -3\end{array}\right]$

$\left[\begin{array}{ccccc}1 & -1 & 2 & \vdots & 1 \\ 2 & -6 & 5 & \vdots & 7 \\ 3 & 5 & 4 & \vdots & -3\end{array}\right] R\left[\begin{array}{ccccc}1 & -1 & 2 & \vdots & 1 \\ 0 & -4 & 1 & \vdots & 5 \\ 0 & 8 & -2 & \vdots & -6\end{array}\right]$ Adding $(-2) R_{1}$ to $R_{2}$ and $\left(-3 R_{1}\right)$ to $R_{2}$.

We have,
$R\left[\begin{array}{ccccc}1 & -1 & 2 & \vdots & 1 \\ 0 & 1 & -\frac{1}{4} & \vdots & -\frac{5}{4} \\ 0 & 8 & -2 & \vdots & -6\end{array}\right] B y-\frac{1}{4} R_{2} \rightarrow R_{2}^{\prime} \quad R\left[\begin{array}{ccccc}1 & 0 & \frac{7}{4} & \vdots & -\frac{1}{4} \\ 0 & 1 & -\frac{1}{4} & \vdots & -\frac{5}{4} \\ 0 & 0 & 0 & \vdots & 4\end{array}\right] \begin{aligned} & \text { By } R_{1}+1 . R_{2} \rightarrow R_{1}^{\prime} \\ & \text { and } R_{2}+(-8) R_{2} \rightarrow R_{2}^{\prime}\end{aligned}$
Thus, the given system is reduced to the equivalent system

$$
\begin{aligned}
x+\frac{7}{4} z & =-\frac{1}{4} \\
y-\frac{1}{4} z & =-\frac{5}{4} \\
0 z & =4
\end{aligned}
$$

The third equation $0 z=4$ has no solution, so the system as a whole has no solution. Thus, the system is inconsistent.
Note We see that in the case of the system (i), the (row) rank of the augmented matrix and the coefficient matrix of the system is the same, that is, 3 which is equal to the number of the variables in the system (i).
Thus, we observe that a linear system is consistent and has a unique solution if the rank of the coefficient matrix is the same as that of the augmented matrix of the system and equal to number of variables.
In the case of the system (ii), the rank of the coefficient matrix is the same as that of the augmented matrix of the system but it is 2 which is less than the number of variables in the system (ii).
Thus, we observe that a system is consistent and has infinitely many solutions if the ranks of the coefficient matrix and the augmented matrix of the system are equal but the rank is less than the number of variables in the system.
In the case of the system (iii), we see that the rank of the coefficient matrix is not equal to the rank of the augmented matrix of the system.
Thus, we observe that a system is inconsistent if the ranks of the coefficient matrix and the augmented matrix of the system are different.

# 4.8.2 Matrix Inversion Method 

The matrix inversion method is a way to solve a system of linear equations using the inverse of a matrix.

$$
x_{1}-2 x_{2}+x_{3}=-4
$$

Example 12 Use matrix inversion method to solve the system $2 x_{1}-3 x_{2}+2 x_{3}=-6$

$$
2 x_{1}+2 x_{2}+x_{3}=5
$$

Solution The matrix form of the given system is

$$
\left[\begin{array}{ccc}
1 & -2 & 1 \\
2 & -3 & 2 \\
2 & 2 & 1
\end{array}\right]\left[\begin{array}{l}
x_{1} \\
x_{2} \\
x_{3}
\end{array}\right]=\left[\begin{array}{c}
-4 \\
-6 \\
5
\end{array}\right]
$$

or $\quad A X=B$
Where

$$
A=\left[\begin{array}{ccc}
1 & -2 & 1 \\
2 & -3 & 2 \\
2 & 2 & 1
\end{array}\right], X=\left[\begin{array}{l}
x_{1} \\
x_{2} \\
x_{3}
\end{array}\right] \text { and } B=\left[\begin{array}{c}
-4 \\
-6 \\
5
\end{array}\right]
$$

As

$$
|A|=\left|\begin{array}{ccc}
1 & -2 & 1 \\
2 & -3 & 2 \\
2 & 2 & 1
\end{array}\right|=\left|\begin{array}{ccc}
1 & -2 & 1 \\
0 & 1 & 0 \\
2 & 2 & 1
\end{array}\right| \quad \text { By } R_{2}+(-2) R_{1} \rightarrow R_{2}
$$

Expanding by $\mathrm{R}_{2}$ we have

$$
=(-1)^{2+2}\left|\begin{array}{ll}
1 & 1 \\
2 & 1
\end{array}\right|=1-2=-1, \text { that is }
$$

$|A| \neq 0$, so the inverse of A exists and (i) can be written as

$$
X=A^{-1} B
$$

Now we find adj $A$.

$$
\begin{aligned}
& \rightarrow \quad[A_{i j}]_{i=3}=\left[\begin{array}{ccc}
-7 & 2 & 10 \\
-1 & -6 & -1 \\
-1 & 0 & 1
\end{array}\right] \\
& \text { Cofactors are } A_{11}=-7, A_{12}=2, A_{13}=10, A_{21}=4 \\
& A_{22}=-1, A_{23}=-6, A_{31}=-1, A_{32}=0, A_{33}=1 \\
& \text { So } \quad \text { adj } A=\left[\begin{array}{ccc}
-7 & 4 & -1 \\
2 & -1 & 0 \\
10 & -6 & 1
\end{array}\right] \\
& \text { and } A^{-1}=\frac{1}{|A|} \operatorname{adj} A=\frac{1}{-1}\left[\begin{array}{ccc}
-7 & 4 & -1 \\
2 & -1 & 0 \\
10 & -6 & 1
\end{array}\right]=\left[\begin{array}{ccc}
7 & -4 & 1 \\
-2 & 1 & 0 \\
-10 & 6 & -1
\end{array}\right]
\end{aligned}
$$

Thus $\left[\begin{array}{l}x_{1} \\ x_{2} \\ x_{3}\end{array}\right]=A^{-1}\left[\begin{array}{c}-4 \\ -6 \\ 5\end{array}\right]=\left[\begin{array}{rrr}7 & -4 & 1 \\ -2 & 1 & 0 \\ -10 & 6 & -1\end{array}\right]\left[\begin{array}{c}-4 \\ -6 \\ 5\end{array}\right]=\left[\begin{array}{c}-28+24+5 \\ 8-6+0 \\ 40-36-5\end{array}\right]$, i.e.,

$$
\left[\begin{array}{l}
x_{1} \\
x_{2} \\
x_{3}
\end{array}\right]=\left[\begin{array}{c}
1 \\
2 \\
-1
\end{array}\right]
$$

Thus, the solution set is $\left\{\left(x_{1}, x_{2}, x_{3}\right)\right\}=\{(1,2,-1)\}$

# 4.8.3 Cramer's Rule 

Consider the system of equations,

$$
\left.\begin{array}{l}
a_{11} x_{1}+a_{12} x_{2}+a_{13} x_{3}=b_{1} \\
a_{21} x_{1}+a_{22} x_{2}+a_{23} x_{3}=b_{2} \\
a_{31} x_{1}+a_{32} x_{2}+a_{33} x_{3}=b_{3}
\end{array}\right\}
$$

These are three linear equations in three variables $x_{1}, x_{2}, x_{3}$ with coefficients and constant terms in the real field R. We write the above system of equations in matrix form as:

$$
A X=B
$$

where

$$
A=\left[a_{i j}\right]_{3 \times 31} X=\left[\begin{array}{l}
x_{1} \\
x_{2} \\
x_{3}
\end{array}\right] \text { and } \quad B=\left[\begin{array}{l}
b_{1} \\
b_{2} \\
b_{3}
\end{array}\right]
$$

We know that the matrix equation (ii) can be written as: $X=A^{-1} B$ (if $A^{-1}$ exists)
We have already proved that $A^{-1}=\frac{1}{|A|} \operatorname{adj} A$

$$
\text { and } \quad \operatorname{adj} A=\left[A_{i j}^{\prime}\right]_{3 \times 3}=\left[\begin{array}{llll}
A_{11} & A_{21} & A_{31} \\
A_{12} & A_{22} & A_{32} \\
A_{13} & A_{23} & A_{33}
\end{array}\right] \quad\left(\because A_{i j}^{\prime}=A_{j i}\right)
$$

Thus $\left[\begin{array}{l}x_{1} \\ x_{2} \\ x_{3}\end{array}\right]=\frac{1}{|A|}\left[\begin{array}{llll}A_{11} & A_{21} & A_{31} \\ A_{12} & A_{22} & A_{32} \\ A_{13} & A_{23} & A_{33}\end{array}\right]\left[\begin{array}{l}b_{1} \\ b_{2} \\ b_{3}\end{array}\right]=\frac{1}{|A|}\left[\begin{array}{llll}A_{1} b_{1}+A_{21} b_{2}+A_{31} b_{3} \\ A_{12} b_{1}+A_{22} b_{2}+A_{32} b_{3} \\ A_{13} b_{1}+A_{23} b_{2}+A_{33} b_{3}\end{array}\right]$

i.e., $\left[\begin{array}{l}x_{1} \\ x_{2} \\ x_{3}\end{array}\right]=\left[\begin{array}{l}\frac{A_{11} b_{1}+A_{21} b_{2}+A_{21} b_{3}}{|A|} \\ \frac{A_{12} b_{1}+A_{22} b_{2}+A_{22} b_{3}}{|A|} \\ \frac{A_{13} b_{1}+A_{23} b_{2}+A_{23} b_{3}}{|A|}\end{array}\right]$
Hence

$$
\begin{aligned}
& x_{1}=\frac{b_{1} A_{11}+b_{2} A_{21}+b_{3} A_{31}}{|A|}=\frac{\left|\begin{array}{lll}
b_{1} & a_{12} & a_{13} \\
b_{2} & a_{22} & a_{23}
\end{array}\right|}{\left|A\right|} \\
& x_{2}=\frac{b_{1} A_{12}+b_{2} A_{22}+b_{3} A_{32}}{|A|}=\frac{\left|\begin{array}{lll}
a_{11} & b_{1} & a_{13} \\
a_{21} & b_{2} & a_{23}
\end{array}\right|}{\left|A\right|} \\
& x_{3}=\frac{b_{1} A_{13}+b_{2} A_{23}+b_{3} A_{32}}{|A|}=\frac{\left|\begin{array}{lll}
a_{11} & a_{12} & b_{1} \\
a_{21} & a_{22} & b_{2}
\end{array}\right|}{\left|A\right|}
\end{aligned}
$$

The method of solving the system with the help of results (iii), (iv) and (v) is often referred to as Cramer's Rule.

Example 15 Use Cramer's rule to solve the system. $\left.\begin{array}{l}3 x_{1}+x_{2}-x_{3}=-4 \\ x_{1}+x_{2}-2 x_{3}=-4 \\ -x_{1}+2 x_{2}-x_{3}=1\end{array}\right\}$

$$
\begin{aligned}
& \text { Here }|A|=\left|\begin{array}{ccc}
3 & 1 & -1 \\
1 & 1 & -2 \\
-1 & 2 & -1
\end{array}\right|=3(-1+4)-1 \cdot(-1-2)-1 \cdot(2+1) \\
& =9+3-3=9 \\
& \text { So, } \quad x_{1}=\frac{\left|\begin{array}{ccc}
-4 & 1 & -1 \\
-4 & 1 & -2 \\
1 & 2 & -1
\end{array}\right|}{9}=\frac{-4(-1+4)-1(4+2)-1(-8-1)}{9}
\end{aligned}
$$

$$
\begin{aligned}
& =\frac{-12-6+9}{9}=\frac{-9}{9}=-1 \\
& \begin{array}{r}
x_{2}=\frac{\left|\begin{array}{ccc}
3 & -4 & -1 \\
1 & -4 & -2
\end{array}\right|}{9}=\frac{3(4+2)+4(-1-2)-1(1-4)}{9} \\
=\frac{18-12+3}{9}=\frac{9}{9}=1
\end{array} \\
& x_{3}=\frac{\left|\begin{array}{ccc}
3 & 1 & -4 \\
1 & 1 & -4 \\
-1 & 2 & 1
\end{array}\right|}{\begin{array}{ll}
9}
9
\end{array}}=\frac{3(1+8)-1(1-4)-4(2+1)}{9}=\frac{27+3-12}{9}=\frac{18}{9}=2
\end{aligned}
$$

Hence $\quad x_{1}=-1, x_{2}=1, x_{3}=2$
Thus, the solution set is $\left\{\left(x_{1}, x_{2}, x_{3}\right)\right\}=\{(-1,1,2)\}$

# 4.9 System of Homogeneous Linear Equations 

The system of following homogeneous linear equations:

$$
\left.\begin{array}{l}
a_{11} x_{1}+a_{12} x_{2}+a_{13} x_{3}=0 \\
a_{21} x_{1}+a_{22} x_{2}+a_{23} x_{3}=0 \\
a_{31} x_{1}+a_{32} x_{2}+a_{33} x_{3}=0
\end{array}\right\}
$$

is always satisfied by $x_{1}=0, x_{2}=0$ and $x_{3}=0$, so such a system is always consistent.
Trivial Solution: The solution $(0,0,0)$ of the above homogeneous system is called the trivial solution.
Non-Trivial Solution: Any other solution of system (i) other than the trivial solution is called a non-trivial solution.

### 4.9.1 Solution of System of Homogeneous Linear Equations by Gaussian Elimination Method

Gaussian Elimination is a systematic method for solving systems of linear equations, named after the German mathematician Carl Friedrich Gauss. It involves performing a series of row operations on the system's augmented matrix to transform it into rowechelon form. Once the matrix is in this simplified form, the solution to the system can be determined through back substitution. This method is widely used due to its efficiency and clarity in solving linear systems.

Example 14 Solve the following system of equations by Gaussian Elimination method:

$$
\begin{aligned}
x+2 y+z & =0 \\
2 x+3 y+4 z & =0 \\
4 x+3 y+2 z & =0
\end{aligned}
$$

Solution The augmented matrix is

$$
\begin{aligned}
& A_{0}=\left[\begin{array}{lll|l}
1 & 2 & 1 & 0 \\
2 & 3 & 4 & 0 \\
4 & 3 & 2 & 0
\end{array}\right] \\
& \underset{=}{E}\left[\begin{array}{rrr|r}
1 & 2 & 1 & 0 \\
0 & -1 & 2 & 0 \\
0 & -5 & -2 & 0
\end{array}\right] B y R_{2}+(-2) R_{1} \rightarrow R_{2}^{\prime} \text { and } R_{3}+(-4) R_{1} \rightarrow R_{3}^{\prime} \\
& \Rightarrow \quad \underset{=}{E}\left[\begin{array}{llll|r}
1 & 2 & 1 & 0 \\
0 & 1 & -2 & 0 \\
0 & -5 & -2 & 0
\end{array}\right] B y(-1) R_{2} \rightarrow R_{2}^{\prime} \\
& \Rightarrow \quad \underset{=}{E}\left[\begin{array}{llll|r}
1 & 2 & 1 & 0 \\
0 & 1 & -2 & 0 \\
0 & 0 & -12 & 0
\end{array}\right] B y R_{3}+5 R_{2} \rightarrow R_{3}^{\prime} \\
& \Rightarrow \quad \underset{=}{E}\left[\begin{array}{llll|r}
1 & 2 & 1 & 0 \\
0 & 1 & -2 & 0 \\
0 & 0 & 1 & 0
\end{array}\right] B y\left(\frac{-1}{12}\right) R_{3} \rightarrow R_{3}^{\prime} \quad \text { (Rank of } A=3=\text { number of variables) }
\end{aligned}
$$

The matrix is in row-echelon form.
By back-substitution, from the third row, $z=0$.
From the second row: $y-2 z=0$

$$
\begin{aligned}
y-2(0) & =0 \\
y & =0
\end{aligned}
$$

From the first row, $x+2 y+z=0$, substituting $y=0$ and $x=0$, we have

$$
\begin{aligned}
x+2(0)+0 & =0 \\
x & =0
\end{aligned}
$$

Thus, the system has only trivial solution, i.e., $(x, y, z)=(0,0,0)$.

Example 15 Solve the following system of equations using Gaussian Elimination Method.

$$
\begin{aligned}
& x_{1}+x_{2}+x_{3}=0 \\
& x_{1}-x_{2}+3 x_{3}=0 \\
& x_{1}+3 x_{2}-x_{3}=0
\end{aligned}
$$

Solution The argumented matrix is

$$
\begin{aligned}
& A_{b}=\left[\begin{array}{rrr}
1 & 1 & 1 & 0 \\
1 & -1 & 3 & 0 \\
1 & 3 & -1 & 0
\end{array}\right] \\
& \underline{\underline{R}}\left[\begin{array}{rrr}
1 & 1 & 1 & 0 \\
0 & -2 & 2 & 0 \\
0 & 2 & -2 & 0
\end{array}\right] \text { By } R_{2}+(-1) R_{1} \rightarrow R_{2}^{\prime} \text { and } R_{3}+(-1) R_{1} \rightarrow R_{2}^{\prime} \\
& \Rightarrow \quad \underline{\underline{R}}\left[\begin{array}{lll}
1 & 1 & 1 & 0 \\
0 & 1 & -1 & 0 \\
0 & 2 & -2 & 0
\end{array}\right] \text { By }\left(-\frac{1}{2}\right) R_{2} \rightarrow R_{2}^{\prime} \\
& \Rightarrow \quad \underline{\underline{R}}\left[\begin{array}{lll}
1 & 1 & 1 & 0 \\
0 & 1 & -1 & 0 \\
0 & 0 & 0 & 0
\end{array}\right] \text { By } R_{3}+(-2) R_{2} \rightarrow R_{3}^{\prime} \quad \text { (Rank of } A<\text { number of variables) }
\end{aligned}
$$

The matrix is in row-echelon form
Thus, the above system is reduced to the equivalent system of equations

$$
\begin{aligned}
x_{1}+x_{2}+x_{3} & =0 \\
x_{2}-x_{3} & =0 \\
0 x_{3} & =0
\end{aligned}
$$

From (i) and (ii), we get

$$
\begin{aligned}
& x_{1}=-x_{2}-x_{3} \\
& x_{2}=x_{3}
\end{aligned}
$$

Substituting $x_{2}=x_{3}$ in (iii), we get

$$
\begin{aligned}
& x_{1}=-x_{3}-x_{3}=2 x_{3} \\
& \Rightarrow \quad x_{1}=-2 x_{3}
\end{aligned}
$$

As $x_{3}$ is arbitrary, so we can find infinitely many values of $x_{1}$ and $x_{2}$ from (iii) and (iv) or the system is satisfied by $x_{1}=-2 t, x_{2}=t$ and $x_{3}=t$ for any value of $t$.

From above examples we observe that:
Rule - I: Homogeneous system of linear equation has only trivial solution if rank of $A=$ number of variables.
Rule - II: Homogeneous system of linear equation has non-trivial solution if rank of $A<$ number of variables.

# 4.10 Applications of Matrices in Real World 

Matrices play a crucial role in solving real-world problems across various fields. In graphic design, they help manipulate images through transformations like scaling, rotation, and reflection. Data encryption and cryptography use matrices for secure communication by encoding and decoding messages. In seismic analysis, engineers use matrices to model and predict earthquake wave behavior. Geometric transformations, such as translation and dilation, rely on matrices to modify shapes in computer graphics. Additionally, social network analysis leverages matrices to represent and analyze relationships between individuals, identifying key influencers and connections in a network.
Transformation or Reflection Matrix is a mathematical tool that represents the reflection of a point or object across a mirror line in a coordinate plane. It's a matrix representation of a reflection transformation. In two dimensions, this typically means reflecting across the $x$-axis, $y$-axis or a line such as $y=x$.

To reflect a matrix over the $x$-axis, we have to multiply it by $\left[\begin{array}{ll}1 & 0 \\ 0 & -1\end{array}\right]$
To reflect a matrix over the $y$-axis, we have to multiply it by $\left[\begin{array}{ll}-1 & 0 \\ 0 & 1\end{array}\right]$
To reflect a matrix over the line $y=x$, we have to multiply it by $\left[\begin{array}{ll}0 & 1 \\ 1 & 0\end{array}\right]$
Example 16 A triangle has the vertices $A(2,3), B(-1,4)$ and $C(3,-2)$. Find the vertices of the reflected triangle over the $x$-axis by using transformation matrix.
Solution To reflect a point across a certain axis or line, we have multiply the point as a column vector by the corresponding transformation matrix.
Here, to reflect the given points over the $x$-axis, we use the transformation matrix $\left[\begin{array}{ll}1 & 0 \\ 0 & -1\end{array}\right]$.

Write the points as column matrices

$$
A=\left[\begin{array}{l}
2 \\
3
\end{array}\right], B=\left[\begin{array}{r}
-1 \\
4
\end{array}\right], C=\left[\begin{array}{r}
3 \\
-2
\end{array}\right]
$$

The vertex $A^{\prime}$ of the reflected image $=\left[\begin{array}{ll}1 & 0 \\ 0 & -1\end{array}\right]\left[\begin{array}{l}2 \\ 3\end{array}\right]=\left[\begin{array}{l}2+0 \\ 0-3\end{array}\right]=\left[\begin{array}{r}2 \\ -3\end{array}\right]=(2,-3)$
The vertex $B^{\prime}$ of the reflected image $=\left[\begin{array}{ll}1 & 0 \\ 0 & -1\end{array}\right]\left[\begin{array}{l}-1 \\ 4\end{array}\right]=\left[\begin{array}{l}-1+0 \\ 0-4\end{array}\right]=\left[\begin{array}{l}-1 \\ -4\end{array}\right]=(-1,-4)$
The vertex $C^{\prime}$ of the reflected image $=\left[\begin{array}{ll}1 & 0 \\ 0 & -1\end{array}\right]\left[\begin{array}{r}3 \\ -2\end{array}\right]=\left[\begin{array}{l}3-0 \\ 0+2\end{array}\right]=\left[\begin{array}{l}3 \\ 2\end{array}\right]=(3,2)$
Thus, the vertices of the reflected triangle are $A^{\prime}(2,-3), B^{\prime}(-1,-4)$ and $C^{\prime}(3,2)$.
Coding is the process of converting a message into a specific format using a code. A code is a system of symbols, words or signals used to represent other words or meanings. It's often used to hide the actual meaning of a message.
To decode a message, we multiply coded matrix by the inverse of the given matrix.
Example17 Use matrix $A=\left[\begin{array}{ll}1 & 2 \\ 3 & 1\end{array}\right]$ to encode the message: ATTACK, where letters $A$ to $Z$ are corresponding to the numbers 1 to 26 .
Solution Here

| A | B | C | D | E | F | G | H | I | J | K | L | M |
| :--: | :--: | :--: | :--: | :--: | :--: | :--: | :--: | :--: | :--: | :--: | :--: | :--: |
| 1 | 2 | 3 | 4 | 5 | 6 | 7 | 8 | 9 | 10 | 11 | 12 | 13 |
| N | 0 | P | Q | R | S | T | U | V | W | X | Y | Z |
| 14 | 15 | 16 | 17 | 18 | 19 | 20 | 21 | 22 | 23 | 24 | 25 | 26 |

Divide the letters of the message into groups of two.

# AT TA CK 

Assign the numbers to these letters and convert each pair of numbers into $2 \times 1$ matrices.

$$
\left[\begin{array}{l}
A \\
T
\end{array}\right]=\left[\begin{array}{l}
1 \\
20
\end{array}\right], \quad\left[\begin{array}{l}
T \\
A
\end{array}\right]=\left[\begin{array}{l}
20 \\
1
\end{array}\right], \quad\left[\begin{array}{l}
C \\
K
\end{array}\right]=\left[\begin{array}{l}
3 \\
11
\end{array}\right]
$$

So, the message in $2 \times 1$ matrices is $\left[\begin{array}{l}1 \\ 20\end{array}\right]\left[\begin{array}{l}20 \\ 1\end{array}\right]\left[\begin{array}{l}3 \\ 11\end{array}\right]$
Now to encode, we multiply, on the left, each matrix of our message by the matrix $A$. i.e., $\left[\begin{array}{ll}1 & 2 \\ 3 & 1\end{array}\right]\left[\begin{array}{l}1 \\ 20\end{array}\right]=\left[\begin{array}{ll}1+40 \\ 3+20\end{array}\right]=\left[\begin{array}{l}41 \\ 23\end{array}\right]$

$$
\begin{aligned}
& {\left[\begin{array}{ll}
1 & 2 \\
3 & 1
\end{array}\right]\left[\begin{array}{l}
20 \\
1
\end{array}\right]=\left[\begin{array}{ll}
20 & +2 \\
60 & +1
\end{array}\right]=\left[\begin{array}{l}
22 \\
61
\end{array}\right]} \\
& {\left[\begin{array}{ll}
1 & 2 \\
3 & 1
\end{array}\right]\left[\begin{array}{l}
3 \\
11
\end{array}\right]=\left[\begin{array}{ll}
3 & +22 \\
9 & +11
\end{array}\right]=\left[\begin{array}{l}
25 \\
20
\end{array}\right]}
\end{aligned}
$$

So, the desired coded message is $\left[\begin{array}{l}41 \\ 23\end{array}\right]\left[\begin{array}{l}22 \\ 61\end{array}\right]\left[\begin{array}{l}25 \\ 20\end{array}\right]$

# EXERCISE 4.3 

1. Find the inverses of the following matrices by using row operations:
(i) $\left[\begin{array}{ccc}2 & 6 & -3 \\ 0 & -2 & 0 \\ -2 & 5 & 6\end{array}\right]$
(ii) $\left[\begin{array}{ccc}1 & 2 & -1 \\ 0 & -2 & 8 \\ 1 & 0 & 2\end{array}\right]$
(iii) $\left[\begin{array}{ccc}1 & 6 & 2 \\ 2 & 13 & 0 \\ 0 & -1 & 1\end{array}\right]$
2. Find the rank of the following matrices:
(i) $\left[\begin{array}{cccc}1 & -1 & 3 & 1 \\ -2 & -6 & 1 & -1 \\ 3 & 1 & 4 & -2\end{array}\right]$
(ii) $\left[\begin{array}{cccc}1 & -2 & 3 \\ 2 & -4 & 6 \\ -1 & 0 & 2 \\ 0 & 1 & -1\end{array}\right]$
(iii) $\left[\begin{array}{cccc}3 & -1 & 3 & 0 & 1 \\ 1 & 2 & -1 & -3 & -2 \\ 2 & 3 & 4 & 2 & 1 \\ 2 & 5 & -2 & -3 & 3\end{array}\right]$
3. Solve the following systems of linear equations by Cramer's rule:

$$
\begin{aligned}
& 2 x+y-z=1 \\
& \text { (i) } \begin{array}{c}
x_{1}+2 x_{2}-3 x_{3}=0 \\
4 x_{1}-x_{2}+x_{3}=5 \\
-2 x_{1}+3 x_{2}+2 x_{3}=3
\end{array} \\
& 2 x_{1}-x_{2}+x_{3}=1 \\
& \text { (iii) } x_{1}+2 x_{2}+2 x_{3}=2 \\
& x_{1}-2 x_{2}-x_{3}=1
\end{aligned}
$$

4. Solve the following systems of linear equations by matrix inversion method:

$$
\begin{aligned}
& x-2 y+z=-1 \\
& \left.\begin{array}{c}
2 x_{1}+x_{2}+3 x_{3}=3 \\
\text { (ii) } x_{1}+3 x_{2}-2 x_{3}=0 \\
-3 x_{1}-x_{2}+2 x_{3}=4
\end{array} \right\} \\
& x+y=2 \\
& \text { (iii) } 2 x-z=1 \\
& 2 y-3 z=-1
\end{aligned}
$$

5. Solve the following systems by reducing their augmented matrices to the echelon form and the reduced echelon forms:

$$
\left.\begin{array}{c}
x_{1}+2 x_{2}-2 x_{3}=-1 \\
2 x_{1}+3 x_{2}+x_{3}=1 \\
5 x_{1}+4 x_{2}-3 x_{3}=1
\end{array}\right\} \quad \begin{gathered}
x+2 y+z=2 \\
\text { (ii) } 2 x+y+2 z=3 \\
2 x+3 y-z=7
\end{gathered} \quad \begin{gathered}
x_{1}+4 x_{2}+x_{3}=2 \\
\text { (iii) } 2 x_{1}+x_{2}-2 x_{3}=9 \\
3 x_{1}+x_{2}-x_{3}=12
\end{gathered}
$$

6. Solve the following systems of homogeneous linear equations by using Gaussian elimination method:

$$
\left.\begin{array}{c}
\left.x+4 y-2 z=0\right] \\
\text { (i) } \left.\begin{array}{c}
2 x+y+5 z=0 \\
5 x+2 y+8 z=0
\end{array}\right\} \\
\left.\begin{array}{c}
\left.x_{1}+4 x_{2}+2 x_{3}=0\right] \\
\text { (ii) } \left.\begin{array}{c}
2 x_{1}+x_{2}-3 x_{3}=0 \\
3 x_{1}+2 x_{2}-4 x_{3}=0
\end{array}\right\} \\
\text { (iii) } \begin{array}{c}
x_{1}+2 x_{2}-x_{3}=0 \\
x_{1}-x_{2}+5 x_{3}=0 \\
2 x_{1}+x_{2}+4 x_{3}=0
\end{array}\right\}
$$

7. A triangle has vertices at $A(4,1), B(-2,5)$ and $C(0,-3)$. Find the vertices of the reflected triangle over the $y$-axis using a transformation matrix.
8. The point $A$ is mapped to $(30,20,-5)$ by the scaling matrix $P_{0} \quad 0 \quad-5 \quad 0$

Find the coordinates of $A$.
[Hint: If $A$ is mapped to $A^{\prime}$ by scaling matrix $P$, then $P A=A^{\prime}$ ]
9. Find the equation of the image of the curve with equation $y=x^{2}$ under the transformation with associated matrix $A^{2}$
10. Use the matrix $A=\left[\begin{array}{llll}1 & 0 & 1 \\ 2 & -1 & 1 \\ 0 & 1 & 2\end{array}\right]$ to encode the message: KEEP IT UP, where letters $A$ to $Z$ are corresponding to the numbers 1 to 26.
11. Decode the message $\left[\begin{array}{l}11 \\ 20 \\ 43\end{array}\right]\left[\begin{array}{l}25 \\ 10 \\ 41\end{array}\right]\left[\begin{array}{l}22 \\ 14 \\ 41\end{array}\right]$ that was encoded using matrix
$A=\left[\begin{array}{llll}1 & 1 & -1 \\ 1 & 0 & 1 \\ 2 & 1 & 1\end{array}\right]$, where the numbers 1 to 26 are corresponding to the letters
$A$ to $Z$, and 27 is representing space or $\sim$.

 # Partial Fractions 

## INTRODUCTION

We have learnt in the previous classes how to add two or more rational fractions into a single rational fraction. For example,
(i) $\frac{1}{x-1}+\frac{2}{x+2}=\frac{3 x}{(x-1)(x+2)}$
and
(ii) $\frac{2}{x+1}+\frac{1}{(x+1)^{2}}+\frac{3}{x-2}=\frac{5 x^{2}+5 x-3}{(x+1)^{2}(x-2)}$

In this unit we shall learn how to reverse the order in (i) and (ii) that is to express a single rational fraction as a sum of two or more single rational fractions which are called Partial Fractions.
Expressing a rational fraction as a sum of partial fractions is called Partial Fraction
Resolution. It is an extremely valuable tool in the study of calculus to decompose a complex rational fraction into a sum of simpler fractions.
An open sentence formed by using the sign of equality ' $=$ ' is called an equation. The equations can be divided into the following two kinds:
Conditional equation: It is an equation in which two algebraic expressions are equal for particular values of the variable e.g.,
(a) $2 x=3$ is a conditional equation and it is true only if $x=\frac{3}{2}$.
(b) $x^{2}+x-6=0$ is a conditional equation and it is true for $x=2,-3$ only.

## Note

For simplicity, a conditional equation is called an equation.
Identity: It is an equation which holds good for all values of the variable e.g.,
(a) $(a+b) x=a x+b x$ is an identity and its two sides are equal for all values of $x$.
(b) $(x+3)(x+4)=x^{2}+7 x+12$ is also an identity which is true for all values of $x$. For convenience, the symbol '"=0" shall be used both for equation and identity.

# 5.1 Rational Fraction 

An expression of the form $\frac{P(x)}{Q(x)}$, where $P(x)$ and $Q(x)$ are polynomials in $x$ with real coefficients and $Q(x) \neq 0$, is called a rational fraction. A rational fraction is of two types.

### 5.1.1 Proper Rational Fraction

A rational fraction $\frac{P(x)}{Q(x)}$ is called a Proper Rational Fraction if the degree of the polynomial $P(x)$ in the numerator is less than the degree of the polynomial $Q(x)$ in the denominator. For example, $\frac{3}{x+1}, \frac{2 x-5}{x^{2}+4}$ and $\frac{9 x^{2}}{x^{3}-1}$ are proper rational fractions or proper fractions.

### 5.1.2 Improper Rational Fraction

A rational fraction $\frac{P(x)}{Q(x)}$ is called an Improper Rational Fraction if the degree of the polynomial $P(x)$ in the numerator is equal to or greater than the degree of the polynomial $Q(x)$ in the denominator.

For example, $\frac{x}{2 x-3}, \frac{(x-2)(x+1)}{(x-1)(x+4)}, \frac{x^{2}-3}{3 x+1}$ and $\frac{x^{3}-x^{2}+x+1}{x^{2}+5}$
are improper rational fractions or improper fractions.
Any improper rational fraction can be reduced by division to a mixed form, consisting of the sum of a polynomial and a proper rational fraction.
For example, $\frac{3 x^{2}+1}{x-2}$ is an improper rational fraction.
By long division we obtain $\frac{3 x^{2}+1}{x-2}=3 x+6+\frac{13}{x-2}$, that is an improper rational fraction $\frac{3 x^{2}+1}{x-2}$ has been reduced to the sum
of a polynomial $3 x+6$ and a proper rational fraction $\frac{13}{x-2}$.

$$
\begin{gathered}
\frac{3 x+6}{x-2} / 3 x^{2}+1 \\
\pm 3 x^{2} \mp 6 x \\
\hline 6 x+1 \\
\pm 6 x+12 \\
\hline 13
\end{gathered}
$$

When a rational fraction is separated into partial fractions, the result is an identity; i.e., it is true for all values of the variable in the domain of the identity.

The evaluation of the coefficients of the partial fractions is based on the following theorem:
"If two polynomials are equal for all values of the variable, then the polynomials have same degree and the coefficients of like powers of the variable in both the polynomials must be equal".
For example,
If $p x^{3}+q x^{3}-a x+b=2 x^{3}-3 x^{2}-4 x+5, \forall x$ then $p=2, q=-3, a=4$ and $b=5$.

# 5.1.3 Resolution of a Rational Fraction $\frac{P(x)}{Q(x)}$ into Partial Frections 

Following are the main points of resolving a rational fraction $\frac{P(x)}{Q(x)}$ into partial fractions:
(i) The degree of $P(x)$ must be less than that of $Q(x)$. If not, divide and work with the remainder theorem.
(ii) Factorize the denominator $Q(x)$ into its irreducible factors, write the rational fraction into partial fractions.
(iii) Multiply the identity with the denominator of left hand side.
(iv) Equate the coefficients of like terms (powers of $x$ ).
(v) Solve the resulting equations for the coefficients.

We now discuss the following cases of partial fractions resolution.
Case I: Resolution of $\frac{P(x)}{Q(x)}$ into partial fractions when $Q(x)$ has only nonrepeated linear factors:
The polynomial $Q(x)$ may be written as:

$$
\begin{aligned}
& Q(x)=\left(x-a_{1}\right)\left(x-a_{2}\right) \ldots\left(x-a_{n}\right) \text {, where } a_{1} \neq a_{2} \neq \ldots \neq a_{n} \\
& \therefore \quad \frac{P(x)}{Q(x)}=\frac{A_{1}}{x-a_{1}}+\frac{A_{2}}{x-a_{2}}+\cdots+\frac{A_{n}}{x-a_{n}} \text { is an identity. }
\end{aligned}
$$

Where $A_{1}, A_{2}, \ldots, A_{n}$ are numbers to be found.
The method is explained by the following examples:
Example 1 Resolve $\frac{7 x+25}{(x+3)(x+4)}$ into partial fractions.
Solution Suppose $\frac{7 x+25}{(x+3)(x+4)}=\frac{A}{x+3}+\frac{B}{x+4}$

Multiplying both sides by $(x+3)(x+4)$, we get

$$
\begin{aligned}
7 x+25 & =A(x+4)+B(x+3) \\
\Rightarrow \quad 7 x+25 & =A x+4 A+B x+3 B \\
\Rightarrow \quad 7 x+25 & =(A+B) x+4 A+3 B
\end{aligned}
$$

this is an identity in $x$.
So, equating the coefficients of like powers of $x$ we have

$$
7=A+B \quad \text { and } \quad 25=4 A+3 B
$$

Solving these equations, we get $A=4$ and $B=3$.
Hence the partial fractions are: $\frac{4}{x+3}+\frac{3}{x+4}$.
Alternative method
Suppose $\quad \frac{7 x+25}{(x+3)(x+4)}=\frac{A}{x+3}+\frac{B}{x+4}$
$\Rightarrow \quad 7 x+25=A(x+4)+B(x+3)$
As two sides of the identity are equal for all values of $x$,
Let us put $x=-3$ and $x=-4$ in it.
For $A$, putting $x+3=0$ i.e., $x=-3$, we get

$$
\begin{aligned}
& -21+25=A(-3+4) \\
& \Rightarrow \quad A=4
\end{aligned}
$$

For $B$, putting $x+4=0$ i.e., $x=-4$, we get

$$
\begin{aligned}
& -28+25=B(-4+3) \\
& \Rightarrow \quad B=3
\end{aligned}
$$

Hence the partial fractions are: $\frac{4}{x+3}+\frac{3}{x+4}$
Example 2 Resolve $\frac{x^{2}-10 x+13}{(x-1)\left(x^{2}-5 x+6\right)}$ into partial fractions.
Solution The polynomial $x^{2}-5 x+6$ in the denominator can be factorized and its factors are $x-3$ and $x-2$.
$\therefore \quad \frac{x^{2}-10 x+13}{(x-1)\left(x^{2}-5 x+6\right)}=\frac{x^{2}-10 x+13}{(x-1)(x-2)(x-3)}$
Suppose $\frac{x^{2}-10 x+13}{(x-1)(x-2)(x-3)}=\frac{A}{x-1}+\frac{B}{x-2}+\frac{C}{x-3}$

$\Rightarrow \quad x^{2}-10 x+13=A(x-2)(x-3)+B(x-1)(x-3)+C(x-1)(x-2)$
which is an identity in $x$.
For $A$, putting $x-1=0$ i.e., $x=1$, we get

$$
\begin{aligned}
& (1)^{2}-10(1)+13=A(1-2)(1-3)+B(1-1)(1-3)+C(1-1)(1-2) \\
& \Rightarrow \quad 1-10+13=A(-1)(-2)+B(0)(-2)+C(0)(-1) \\
& 4=2 A \\
& \therefore \quad A=2
\end{aligned}
$$

For $B$, putting $x-2=0$ i.e., $x=2$, we get

$$
\begin{aligned}
& (2)^{2}-10(2)+13=A(0)(2-3)+B(2-1)(2-3)+C(2-1)(0) \\
& \Rightarrow \quad 4-20+13=B(1)(-1) \\
& \Rightarrow \quad-3=-B \\
& \therefore \quad B=3
\end{aligned}
$$

For $C$, putting $x-3=0$ i.e., $x=3$, we get

$$
\begin{aligned}
& (3)^{2}-10(3)+13=A(3-2)(0)+B(3-1)(0)+C(3-1)(3-2) \\
& \Rightarrow \quad 9-30+13=C(2)(1) \\
& \Rightarrow \quad-8=2 C \\
& \therefore \quad C=-4
\end{aligned}
$$

Hence, $\frac{x^{2}-10 x+13}{(x-1)\left(x^{2}-5 x+6\right)}=\frac{2}{x-1}+\frac{3}{x-2}-\frac{4}{x-3}$
Example 3 Resolve $\frac{2 x^{3}+x^{2}-x-3}{x(2 x+3)(x-1)}$ into partial fractions.
Solution $\frac{2 x^{3}+x^{2}-x-3}{x(2 x+3)(x-1)}$ is an improper fraction so, first transform it into mixed form.
Denominator $=x(2 x+3)(x-1)=2 x^{3}+x^{2}-3 x$
$\therefore$ Dividing $2 x^{3}+x^{2}-x-3$ by $2 x^{3}+x^{2}-3 x$,
we have
Quotient $=1$ and Remainder $=2 x-3$

$$
\begin{aligned}
& 2 x^{3}+x^{2}-3 x \longdiv { 2 x ^ { 3 } + x ^ { 2 } - x - 3 } \\
& -2 x^{3} \pm x^{2} \mp 3 x \\
& 2 x-3
\end{aligned}
$$

$\therefore \quad \frac{2 x^{3}+x^{2}-x-3}{x(2 x+3)(x-1)}=1+\frac{2 x-3}{x(2 x+3)(x-1)}$
Suppose $\quad \frac{2 x-3}{x(2 x+3)(x-1)}=\frac{A}{x}+\frac{B}{2 x+3}+\frac{C}{x-1}$

$$
\Rightarrow \quad 2 x-3=A(2 x+3)(x-1)+B(x)(x-1)+C(x)(2 x+3)
$$

which is an identity in $x$.
For $A$, putting $x=0$ in the identity, we get $A=1$
For $B$, putting $2 x+3=0 \Rightarrow x=-\frac{3}{2}$ in the identity, we get $B=-\frac{8}{5}$
For $C$, putting $x-1=0 \Rightarrow x=1$ in the identity, we get $C=-\frac{1}{5}$
Hence, $\frac{2 x^{3}+x^{2}-x-3}{x(2 x+3)(x-1)}=1+\frac{1}{x}-\frac{8}{5(2 x+3)}-\frac{1}{5(x-1)}$
Case II: When $Q(x)$ has repeated linear factors:
If the polynomial $Q(x)$ has a repeated linear factors $(x-a)^{n}, n \geq 2$ and $n$ is $a$ positive integer, then $\frac{P(x)}{Q(x)}$ may be written as the following identity:

$$
\frac{P(x)}{Q(x)}=\frac{A}{(x-a)}+\frac{A_{2}}{(x-a)^{2}}+\cdots+\frac{A_{n}}{(x-a)^{n}}
$$

where $A_{1}, A_{2}, \ldots, A_{n}$ are numbers to be found.
The method is explained by the following examples:
Example 4 Resolve $\frac{x^{3}+x-1}{(x+2)^{3}}$ into partial fractions.
Solution Suppose $\frac{x^{3}+x-1}{(x+2)^{3}}=\frac{A}{x+2}+\frac{B}{(x+2)^{2}}+\frac{C}{(x+2)^{3}}$

$$
\begin{aligned}
& \Rightarrow x^{2}+x-1=A(x+2)^{2}+B(x+2)+C \\
& \Rightarrow x^{2}+x-1=A\left(x^{2}+4 x+4\right)+B(x+2)+C
\end{aligned}
$$

For C , putting $x+2=0$, i.e., $x=-2$ in (i), we get

$$
\begin{aligned}
& (-2)^{2}+(-2)-1=A(0)+B(0)+C \\
& \Rightarrow \quad 1=C
\end{aligned}
$$

Equating the coefficients of $x^{2}$ and $x$ in (ii), we get $A=1$

$$
\text { and } \quad 1=4 A+B
$$

$$
\Rightarrow \quad 1=4+B \Rightarrow B=-3
$$

Hence, $\frac{x^{2}+x-1}{(x+2)^{3}}=\frac{1}{x+2}-\frac{3}{(x+2)^{2}}+\frac{1}{(x+2)^{3}}$
Example 5 Resolve $\frac{1}{(x+1)^{2}\left(x^{2}-1\right)}$ into partial fractions.
Solution Here denominator $=(x+1)^{2}\left(x^{2}-1\right)$

$$
=(x+1)^{2}(x+1)(x-1)=(x+1)^{2}(x-1)
$$

$$
\therefore \quad \frac{1}{(x+1)^{2}\left(x^{2}-1\right)}=\frac{1}{(x+1)^{3}(x-1)}
$$

Suppose $\quad \frac{1}{(x-1)(x+1)^{3}}=\frac{A}{x-1}+\frac{B}{x+1}+\frac{C}{(x+1)^{2}}+\frac{D}{(x+1)^{3}}$

$$
\begin{aligned}
& \Rightarrow \quad 1=A(x+1)^{3}+B(x+1)^{2}(x-1)+C(x-1)(x+1)+D(x-1) \\
& \Rightarrow \quad 1=A\left(x^{3}+3 x^{2}+3 x+1\right)+B\left(x^{3}+x^{2}-x-1\right)+C\left(x^{2}-1\right)+D(x-1) \\
& \Rightarrow \quad 1=(A+B) x^{3}+(3 A+B+C) x^{2}+(3 A-B+D) x+(A-B-C-D)
\end{aligned}
$$

For $A$, putting $x-1=0 \Rightarrow x=1$ in (i), we get

$$
1=A(2)^{3} \quad \Rightarrow A=\frac{1}{8}
$$

For $D$, putting $x+1=0 \Rightarrow x=-1$ in (i), we get

$$
1=D(-1-1) \quad \Rightarrow \quad D=-\frac{1}{2}
$$

Equating the coefficients of $x^{3}$ and $x^{2}$ in (ii), we get

$$
0=A+B \quad \Rightarrow \quad B=-A \quad \Rightarrow \quad B=-\frac{1}{8}
$$

and

$$
0=3 A+B+C \Rightarrow 0=\frac{3}{8}-\frac{1}{8}+C \Rightarrow C=-\frac{1}{4}
$$

Hence the partial fractions are:

$$
\frac{\frac{1}{8}}{x-1}+\frac{-\frac{1}{8}}{x+1}+\frac{-\frac{1}{4}}{(x+1)^{2}}+\frac{-\frac{1}{2}}{(x+1)^{3}}=\frac{1}{8(x-1)}-\frac{1}{8(x+1)}-\frac{1}{4(x+1)^{2}}-\frac{1}{2(x+1)^{3}}
$$

# EXERCISE 5.1 

## Resolve the following into partial fractions:

1. $\frac{2}{x^{2}-1}$
2. $\frac{a-b}{(x-a)(x-b)},(a \neq b)$
3. $\frac{x^{2}+1}{(x+1)(x-1)}$
4. $\frac{2 x+3}{(x+1)(x+2)(x+3)}$
5. $\frac{x^{2}+4 x+5}{(x+1)\left(x^{2}+5 x+6\right)}$
6. $\frac{4 x^{3}+5 x^{3}-3 x-2}{x^{2}-1}$
7. $\frac{3 x^{2}-12 x+11}{(x-1)(x-2)(x-3)}$
8. $\frac{(x-1)(x-2)(x-3)}{(x-4)(x-5)(x-6)}$
9. $\frac{x^{2}}{\left(x^{2}+a\right)\left(x^{2}+b\right)\left(x^{2}+c\right)}$
10. $\frac{x+1}{(x-1)^{2}}$
11. $\frac{x^{2}+x}{\left(x^{2}-1\right)^{2}}$
12. $\frac{3 x^{2}+4 x-5}{(x-1)^{3}}$
13. $\frac{1}{x(x+1)^{3}}$
14. $\frac{4 x^{2}-3 x+1}{(x+1)(x-1)^{2}}$
15. $\frac{12 x^{2}-48}{(x-2)^{2}(x+2)^{2}}$

## Case III: When $Q(x)$ contains non-repeated irreducible quadratic factors

Definition: A quadratic factor is irreducible if it cannot be written as the product of two linear factors with real coefficients. For example, $x^{2}+x+1$ and $x^{2}+3$ are irreducible quadratic factors.

If the polynomial $Q(x)$ contains non-repeated irreducible quadratic factors then $\frac{P(x)}{Q(x)}$ may be written as the identity having partial fractions of the form:

$$
\frac{A x+B}{a x^{2}+b x+c} \text { where } A \text { and } B \text { are the numbers to be found. }
$$

The method is explained by the following examples:
Example 6 Resolve $\frac{3 x-11}{\left(x^{2}+1\right)(x+3)}$ into partial fractions.
Solution Suppose $\frac{3 x-11}{\left(x^{2}+1\right)(x+3)}=\frac{A x+B}{x^{2}+1}+\frac{C}{x+3}$

$$
\begin{aligned}
& \Rightarrow \quad 3 x-11=(A x+B)(x+3)+C\left(x^{2}+1\right) \\
& \Rightarrow \quad 3 x-11=(A+C) x^{2}+(3 A+B) x+(3 B+C)
\end{aligned}
$$

For $C$, putting $x+3=0 \quad \Rightarrow \quad x=-3$ in (i), we get

$$
-9-11=C(9+1) \quad \Rightarrow \quad C=-2
$$

Equating the coefficients of $x^{2}$ and $x$ in (ii), we get

$$
\begin{aligned}
& 0=A+C \Rightarrow A=-C \quad \Rightarrow A=2 \\
& \text { and } \quad 3=3 A+B \Rightarrow B=3-3 A \Rightarrow B=3-6 \Rightarrow B=-3 \\
& \text { Hence, } \frac{3 x-11}{\left(x^{2}+1\right)(x+3)}=\frac{2 x-3}{x^{3}+1}-\frac{2}{x+3}
\end{aligned}
$$

Example 7 Resolve $\frac{4 x^{2}+8 x}{x^{4}+2 x^{2}+9}$ into partial fractions.
Solution Here, denominator $=x^{4}+2 x^{2}+9=\left(x^{2}+2 x+3\right)\left(x^{2}-2 x+3\right)$

$$
\therefore \quad \frac{4 x^{2}+8 x}{x^{4}+2 x^{2}+9}=\frac{4 x^{2}+8 x}{\left(x^{2}+2 x+3\right)\left(x^{2}-2 x+3\right)}
$$

Suppose

$$
\begin{aligned}
& \frac{4 x^{2}+8 x}{\left(x^{2}+2 x+3\right)\left(x^{2}-2 x+3\right)}=\frac{A x+B}{x^{2}+2 x+3}+\frac{C x+D}{x^{2}-2 x+3} \\
& \Rightarrow \quad 4 x^{2}+8 x=(A x+B)\left(x^{2}-2 x+3\right)+(C x+D)\left(x^{2}+2 x+3\right) \\
& \Rightarrow \quad 4 x^{2}+8 x=(A+C) x^{3}+(-2 A+B+2 C+D) x^{2} \\
&+(3 A-2 B+3 C+2 D) x+3 B+3 D
\end{aligned}
$$

which is an identity in $x$.
Equating the coefficients of $x^{3}, x^{2}, x, x^{0}$ in (i), we have

$$
\begin{aligned}
& 0=A+C \\
& 4=-2 A+B+2 C+D \\
& 8=3 A-2 B+3 C+2 D \\
& 0=3 B+3 D
\end{aligned}
$$

Solving (ii), (iii), (iv) and (v), we get

$$
A=1, B=2, C=-1 \text { and } D=-2
$$

Hence, $\frac{4 x^{2}+8 x}{x^{4}+2 x^{2}+9}=\frac{x+2}{x^{2}+2 x+3}+\frac{-x-2}{x^{2}-2 x+3}$
Case IV: When $Q(x)$ has repeated irreducible quadratic factors
If the polynomial $Q(x)$ contains a repeated irreducible quadratic factors $\left(a x^{2}+b x+c\right)^{n}$, $n \geq 2$ and $n$ is a positive integer, then $\frac{P(x)}{Q(x)}$ may be written as the following identity:

$$
\frac{P(x)}{Q(x)}=\frac{A_{1} x+B_{1}}{\alpha x^{2}+b x+c}+\frac{A_{2} x+B_{2}}{\left(a x^{2}+b x+c\right)^{2}}+\ldots+\frac{A_{n} x+B_{n}}{\left(a x^{2}+b x+c\right)^{n}}
$$

where $A_{1}, B_{1}, A_{2}, B_{2}, \ldots, A_{n}, B_{n}$ are numbers to be found. The method is explained through the following example:

Example 5 Resolve $\frac{4 x^{2}}{\left(x^{2}+1\right)^{2}(x-1)}$ into partial fractions.
Solution Let $\frac{4 x^{2}}{\left(x^{2}+1\right)^{2}(x-1)}=\frac{A x+B}{x^{2}+1}+\frac{C x+D}{\left(x^{2}+1\right)^{2}}+\frac{E}{x-1}$
$\Rightarrow 4 x^{2}=(A x+B)\left(x^{2}+1\right)(x-1)+(C x+D)(x-1)+E\left(x^{2}+1\right)^{2}$
$\Rightarrow \quad 4 x^{2}=(A+E) x^{4}+(-A+B) x^{3}+(A-B+C+2 E) x^{2}$

$$
+(-A+B-C+D) x+(-B-D+E)
$$

For $E$, putting $x-1=0 \quad \Rightarrow x=1$ in (i), we get

$$
4=E(1+1)^{2} \quad \Rightarrow \quad E=1
$$

Equating the coefficients of $x^{4}, x^{3}, x^{2}, x$, in (ii), we get

$$
\begin{aligned}
& 0=A+E \quad \Rightarrow \quad A=-E \quad \Rightarrow \quad A=-1 \\
& 0=-A+B \quad \Rightarrow \quad B=A \quad \Rightarrow \quad B=-1 \\
& 4=A-B+C+2 E \\
& \Rightarrow \quad C=4-A+B-2 E=4+1-1-2 \Rightarrow \quad C=2 \\
& \text { and } \quad 0=-A+B-C+D \\
& \Rightarrow \quad D=A-B+C=-1+1+2=2 \quad \Rightarrow \quad D=2
\end{aligned}
$$

Hence, $\frac{4 x^{2}}{\left(x^{2}+1\right)^{2}(x-1)}=\frac{x-1}{x^{2}+1}+\frac{2 x+2}{\left(x^{2}+1\right)^{2}}+\frac{1}{x-1}$

# EXERCISE 5.2 

## Resolve into partial fractions:

1. $\frac{2 x^{2}+3 x+3}{(x+1)\left(x^{2}+1\right)}$
2. $\frac{2 x+1}{(x-2)\left(x^{2}+3 x+5\right)}$
3. $\frac{2 x+32}{(x-2)\left(x^{2}+2\right)^{2}}$
4. $\frac{3 x^{2}+3}{x^{3}+1}$
5. $\frac{x^{4}}{x^{4}+2 x^{2}+1}$
6. $\frac{6 x^{4}+40 x^{2}}{\left(4-x^{2}\right)\left(x^{2}+4\right)^{2}}$

# Sequences and Series 

## INTRODUCTION

In this unit, students will leam to analyze and solve problems involving arithmetic, geometric, and harmonic sequences and series, including their real-world applications. Students will identify various sequence types, compute finite and infinite sums, and utilize sigma notation. Additionally, they will explore practical scenarios such as motor vehicle leasing, investment planning, and financial calculations. This unit also emphasizes applying these concepts to diverse fields, including healtheare, finance, and traffic modeling. Finally, students will be able to solve both theoretical and reallife problems using sequences and series effectively.
Let us observe the following pattern of numbers:
(i) $5,11,17,23, \ldots$
(ii) $6,12,24,48, \ldots$
(iii) $4,2,0,-2,-4, \ldots$
(iv) $\frac{2}{3}, \frac{4}{9}, \frac{8}{27}, \frac{16}{81}, \ldots$

In example (i), every number (except 5) is formed by adding 6 to the previous numbers. Hence a specific pattern is followed in the arrangement of these numbers. Similarly, in example (ii), every number is obtained by multiplying the previous number by 2. Similar cases are followed in example (iii) and (iv). When a set of numbers follows a pattern and there is a clear rule for finding next number in the pattern, then we have sequence as in above examples.

### 6.1 Sequence

A sequence is a function whose domain is the set $N$ of all natural numbers, whereas the range may be any subset of real numbers or complex numbers. The numbers in a sequence are called its terms. We denote the first term of a sequence as $a_{1}$, second term as $a_{2}$ and so on. The $n^{\text {th }}$ term of a sequence is denoted by $a_{n}$, which may also be referred to as the general term of the sequence, and the terms immediately preceding it are called the $(n-1)^{\text {st }}$ term, the $(n-2)^{\text {nd }}$ term and so on.

### 6.1.1 Finite and Infinite Sequences

1. A sequence which consists of a finite number of terms is called a finite sequence. For example, $2,5,8,11,14,17,20,23$ is a finite sequence of 8 terms.
2. A sequence which consists of an infinite number of terms is called an infinite sequence. For example, $3,10,17,24, \ldots$ is an infinite sequence, or more generally as $3,10,17,24, \ldots, 7 n-4, \ldots$ to show how each term was generated.

Note If a sequence is given, then we can find its $n^{\text {th }}$ term and if the $n^{\text {th }}$ term of a sequence is given then we can find the terms of the sequence.
Example 1 Find the first four terms of the following sequences whose $n^{\text {th }}$ terms are given:
(i) $a_{n}=3 n+1$
(ii) $a_{n}=3 n^{2}-3$

Solution (i) $a_{n}=3 n+1$
Substituting $n=1,2,3$ and 4 we have

$$
a_{1}=3(1)+1=3+1=4
$$

Similarly, $\quad a_{2}=3(2)+1=6+1=7$

$$
\begin{aligned}
& a_{3}=3(3)+1=9+1=10 \\
& a_{4}=3(4)+1=12+1=13
\end{aligned}
$$

The first four terms of the sequence are $4,7,10,13$.
(ii) $a_{n}=3 n^{2}-3$

Substituting $n=1,2,3$ and 4 we have

$$
a_{1}=3(1)^{2}-3=0
$$

Similarly, $\quad a_{2}=3(2)^{2}-3=3(4)-3=12-3=9$

$$
\begin{aligned}
& a_{3}=3(3)^{2}-3=3(9)-3=27-3=24 \\
& a_{4}=3(4)^{2}-3=3(16)-3=48-3=45
\end{aligned}
$$

The first four terms of the sequence are $0,9,24,45$.
Sequences of numbers are also called progressions. Depending on the pattern, the progressions are classified as follows:
(i) Arithmetic progression
(ii) Geometric progression
(iii) Harmonic progression

# EXERCISE 6.1 

1. Find the next four terms of each sequence.
(i) $12,16,20, \ldots$
(ii) $3,1,-1, \ldots$
2. Write down the first three terms of each of the following sequences:
(i) $a_{n}=3 n+5$
(ii) $a_{n+1}=4 a_{n}-7$ and $a_{1}=3$
(iii) $a_{n}=(n-3)(n+1)$
(iv) $a_{1}=-1, a_{n+1}=\frac{3}{a_{n}+2}$
(v) $a_{n}=8-\frac{20}{3+n}$
(vi) $a_{1}=1, a_{n+1}=\left(3 a_{n}+2\right)^{2}$
(vii) $a_{n}=(-2 n)^{2}$
(viii) $a_{n}=(-1)^{n} 7 n^{2}$
3. An expression for the $n^{\text {th }}$ triangular number is $\frac{n(n+1)}{2}$. Write down the $15^{\text {th }}$ triangular number. Make a triangle of dots by taking $n=5$.

4. Write down the $n^{\text {th }}$ term of each of the following sequences:
(i) $1,4,9, \ldots$
(ii) $1,1+2,1+2+3, \ldots$
(iii) $a_{1} b_{1}, a_{2} b_{2}, a_{3} b_{3}, \ldots$
(iv) $x, 2 x^{2}, 3 x^{3}, \ldots$
(v) $a_{1}, a_{1}+d, a_{1}+2 d, \ldots$
(vi) $a_{1}, a_{1} r, a_{1} r^{2}, \ldots$
(vii) $\frac{a_{1}}{b_{1}+c_{1}}, \frac{2 a_{2}}{b_{2}+c_{2}}, \frac{3 a_{3}}{b_{3}+c_{3}}, \ldots$
(viii) $\frac{1}{a_{1}}, \frac{1}{a_{1}+d}, \frac{1}{a_{1}+2 d}, \ldots$

# 6.2 Arithmetic Progression or Arithmetic Sequence (A.P.) 

A sequence $\left\{a_{n}\right\}$ is called an arithmetic sequence or arithmetic progression (A.P.), if $a_{n}-a_{n-1}$ is the same number for all $n \in N$ and $n>1$. The difference $a_{n}-a_{n-1}(n>1)$ i.e., the difference of two consecutive terms of an A.P., is called the common difference and is usually denoted by $d$.
Thus, an arithmetic progression is a sequence in which each term after the first is obtained by adding fixed constant to the previous term. This fixed constant is called common difference of the arithmetic progression.
For example: Following sequences are in A.P.
(i) $1,3,5,7, \ldots$ (common difference is 2 )
(ii) $54,51,48, \ldots$ (common difference is -3 )

An arithmetic progression with $n$ terms can be written as:

$$
a_{1}, a_{1}+d, a_{1}+2 d, \ldots, a_{1}+(n-1) d
$$

The $n^{\text {th }}$ term of an arithmetic progression can be written as:

$$
a_{n}=a_{1}+(n-1) d
$$

## Note

(i) $1^{n}, 2^{\text {nd }}, 3^{\text {rd }}$ and $n^{\text {th }}$ terms of an A.P. are denoted by $a_{1}, a_{2}, a_{3}$ and $a_{n}$ respectively.
(ii) $n^{\text {th }}$ term from the end of an $A . P$. is $(m-n+1)^{\text {th }}$ term where ' $m$ ' denotes the total number of terms of an A.P.
(iii) Three numbers $a, b, c$ are in $A . P$. if and only if $2 b=a+c$.
(iv) Any term (except first and last) in an A.P. is equal to half of the sum of two terms equidistant from it.
(v) If the term $a_{1}$ is unknown or not given, the $n^{\text {th }}$ term can be written as $a_{n}=a_{m}+(n-m) d, n \geq m$. Note that the subscript of the given term and coefficient of $d$ sum to $n$.
The middle term of an A.P. depends upon the number of terms, for example
(i) $1,3,5,7,9,11$ is an A.P. with $n=6$
(ii) $1,3,5,7,9,11,13$ is an A.P. with $n=7$

i.e., If the total number of terms of an A.P. is even, then there are two middle terms i.e., $\left(\frac{n}{2}\right)^{n}$ and $\left(\frac{n}{2}+1\right)^{n}$ where $n$ represent the number of terms. In example (i) 5,7 are two middle terms.
If the total number of terms of an A.P. is odd, then there is only one middle term i.e., $\left(\frac{n+1}{2}\right)^{n}$ term. In example (ii) 7 is the only middle term.

# 6.2.1 Selection of terms in A.P. 

(i) Three consecutive terms of an A.P. can be chosen as $a-d, a, a+d$ or $a, a+d$, or $a+2 d$
(ii) Four consecutive term of an A.P. may be written like $a-3 d, a-d, a+d, a+3 d$ or $a, a+d, a+2 d, a+3 d$.
(iii) Last four consecutive terms if $\ell$ is the last term can be written as below:

$$
\ell-3 d, \ell-2 d, \ell-d, \ell
$$

If each term of an A.P. is increased or decreased, multiplied or divided by same non-zero number, then the resulting sequence is also an A.P. that is, if $a_{1}, a_{2}, a_{3}, \ldots, a_{n}, \ldots$ are in A.P. with common difference $d$ then
(i) $a_{1} \pm k, a_{2} \pm k, \ldots, a_{n} \pm k, \ldots$ are also in A.P. with common difference ' $d$ '.
(ii) $k a_{1}, k a_{2}, \ldots, k a_{n}, \ldots$ are also in A.P. with common difference ' $k d$ '.
(iii) $\frac{a_{1}}{k}, \frac{a_{2}}{k}, \ldots, \frac{a_{n}}{k}, \ldots$ are also in A.P. with common difference $\frac{d}{k}$.
(iv) Term by term addition or subtraction of two A.Ps. is also an A.P. i.e., If $a_{1}, a_{2}, a_{3}, \ldots a_{n}, \ldots$ and $b_{1}, b_{2}, b_{3}, \ldots b_{n}, \ldots$ are in A.P., then $a_{1} \pm b_{1}, a_{2} \pm b_{2}$, $a_{2} \pm b_{3}, \ldots$ are also in A.P.
Example 2 Find the general term and the eleventh term of the A.P. whose first term and the common difference are 2 and -3 respectively. Also write its first four terms.
Solution
Here, $a_{1}=2, d=-3$
We know that $a_{n}=a_{1}+(n-1) d$
So,

$$
\begin{aligned}
a_{n} & =2+(n-1)(-3)=2-3 n+3 \\
a_{n} & =5-3 n
\end{aligned}
$$

Thus, the general term of the A.P. is $5-3 n$

Putting $n=11$ in (i), we have

$$
\begin{aligned}
a_{11} & =5-3(11) \\
& =5-33=-28
\end{aligned}
$$

We can find $a_{2}, a_{3}, a_{4}$ by putting $n=2,3,4$ in (i), that is,

$$
\begin{aligned}
& a_{2}=5-3(2)=-1 \\
& a_{3}=5-3(3)=-4 \\
& a_{4}=5-3(4)=-7
\end{aligned}
$$

Hence, the first four terms of the sequence are: $2,-1,-4,-7$.
Example 3 If the $5^{\text {th }}$ term of an $A . P$. is 13 and $17^{\text {th }}$ term is 49 , find $a_{n}$ and $a_{13}$.
Solution Given that $a_{5}=13$ and $a_{17}=49$
Putting $n=5$ in $a_{n}=a_{1}+(n-1) d$, we have $a_{5}=a_{1}+(5-1) d$

$$
\begin{aligned}
& a_{5}=a_{1}+4 d \\
& 13=a_{1}+4 d \quad\left(\because a_{5}=13\right) \\
& \text { Also } \quad a_{17}=a_{1}+(17-1) d \\
& 49=a_{1}+16 d \quad\left(\because a_{1}+49\right) \\
& 49=\left(a_{1}+4 d\right)+12 d \\
& 49=13+12 d \quad \text { by (i) } \\
& \Rightarrow \quad 12 d=36 \quad \Rightarrow \quad d=3 \\
& \text { From (i), } a_{1}=13-4 d=13-4(3)=13-12=1 \\
& \text { Thus } \quad a_{n}=1+(n-1)(3)=3 n-2 \text { and } \\
& a_{13}=3(13)-2=39-2=37
\end{aligned}
$$

Example 4 Find the number of terms in the A.P. ; if $a_{1}=3, d=7$ and $a_{n}=59$
Solution Using $a_{n}=a_{1}+(n-1) d$, we have

$$
\begin{aligned}
& 59=3+(n-1) \times 7 \quad\left(\because a_{n}=59, a_{1}=3 \text { and } d=7\right) \\
& 56=(n-1) \times 7 \Rightarrow n-1=8 \Rightarrow n=9
\end{aligned}
$$

Thus, the terms in the A.P. are 9.
Example 5 If $a_{n-2}=3 n-11$ find the $n^{\text {th }}$ term of the sequence.
Solution Replacing $n$ by $n+2$, we have

$$
\begin{aligned}
a_{n+2-2} & =3(n+2)-11 \\
a_{n} & =3 n+6-11 \\
a_{n} & =3 n-5
\end{aligned}
$$

# EXERCISE 6.2 

1. Find the common difference and write the next two terms of each arithmetic sequence.
(i) $9,16,23, \ldots$
(ii) $5,5+\sqrt{2}, 5+2 \sqrt{2}, \ldots$
2. Write the first three terms of each arithmetic sequence, with given information.
(i) $a_{1}=2, d=13$
(ii) $a_{1}=12, d=-13$
3. Find $a_{n+1}$ and $a_{2 n}$ if $a_{n}=4+3 n$
4. Find the indicated term of each of the following arithmetic sequenecs:
(i) $a_{1}=3, d=7, a_{14}$
(ii) $8,3,-2, \ldots, a_{12}$
5. The $18^{\text {th }}$ and $30^{\text {th }}$ terms of an arithmetic sequence are 367 and 499 respectively. How many terms of this sequence are less than 1000 ?
6. Is 301 a term of the A.P. $5,11,17, \ldots$ ?
7. If $2 x, x+8,3 x+1$ are in A.P., then find the value of $x$
8. Which term of the A.P., $3,8,13, \ldots$ is 123 ?
9. Which term of the A.P., $30,29.5,29, \ldots$ is the first negative term?
10. The $7^{\text {th }}$ and $21^{\text {st }}$ terms of an A.P., are 37 and 107 respectively. Find the A.P. and its $100^{\text {th }}$ term.
11. If $\frac{1}{a-c}, \frac{1}{b-c}, \frac{1}{b-a}$ are in A.P., the show that $\frac{a-b}{a-c}=\frac{a-c}{b-a}$.
12. How many numbers of three digits are divisible by 7 ?
13. Find the $8^{\text {th }}$ term from the end of the A.P., $8,11,14, \ldots, 185$.
14. Find the $n^{\text {th }}$ term of the progression $\left(\frac{3}{7}\right)^{10},\left(\frac{10}{7}\right)^{10},\left(\frac{17}{7}\right)^{10}, \ldots$. Is the progression an A.P.?
15. If the arithmetie progressions $3,10,17, \ldots$ and $63,65,67, \ldots$ are such that their $n^{\text {th }}$ terms are equal, then find the value of $n$.
16. If the $p^{\text {th }}$ term of an A.P. is $q$ and the $q^{\text {th }}$ term is $p$, prove that its $n^{\text {th }}$ term is $(p+q-n)$.
17. If $\frac{1}{a}, \frac{1}{b}$ and $\frac{1}{c}$ are in A.P., show that $b=\frac{2 a c}{a+c}$.
18. If $\frac{1}{a}, \frac{1}{b}$ and $\frac{1}{c}$ are in A.P., show that the common difference is $\frac{a-c}{2 a c}$.
19. If $a_{k}$ and $a_{m}$ denotes two different terms of an A.P., show that its $n^{\text {th }}$ term is $a_{k}+(n-k)\left(\frac{a_{k}-a_{m}}{k-m}\right)$.

20. If $a_{1}, a_{2}, a_{3}, \ldots, a_{n}$ are positive and in A.P., prove that

$$
\frac{1}{\sqrt{a_{1}}+\sqrt{a_{2}}}+\frac{1}{\sqrt{a_{2}}+\sqrt{a_{3}}}+\ldots+\frac{1}{\sqrt{a_{n-1}}+\sqrt{a_{n}}}=\frac{n-1}{\sqrt{a_{1}}+\sqrt{a_{n}}}
$$

21. If the roots of the equation $(b-c) x^{2}+(c-a) x+(a-b)=0$ are equal. Show that $a, b, c$ are in A.P.
22. If the sides of a right-angled triangle are in A.P., find the ratio of its sides.
23. If the $n^{\text {th }}$ term of a progression is a linear expression in $n$, then prove that this progression is an A.P.

# 6.3 Arithmetic Mean (A.M.) 

A number $A$ is said to be the A.M. between the two numbers $a$ and $b$ if $a, A, b$ are in A.P. If $d$ is the common difference of this A.P., then $A-a=d$ and $b-A=d$.

$$
\begin{aligned}
& \text { Thus } A-a=b-A \\
& \text { or } \quad 2 A=a+b \\
& \Rightarrow \quad A=\frac{a+b}{2}
\end{aligned} \quad \text { Note if } A_{1} A_{2}, A_{3}, \ldots, A_{n} \text { are said to be } n \text { A.Ms. between two numbers } a \text { and } b \text {, then } \\
& a_{1} A_{1}, A_{2}, A_{3}, \ldots, A_{n}, b \text { are in A.P. }
$$

Example 6 Find three A.Ms. between $\sqrt{2}$ and $3 \sqrt{2}$.
Solution Let $A_{1}, A_{2}, A_{3}$ be three A.Ms. between $\sqrt{2}$ and $3 \sqrt{2}$. Then,

$$
\sqrt{2}, A_{1}, A_{2}, A_{3}, 3 \sqrt{2} \text { are in } A . P
$$

Here $a_{1}=\sqrt{2}, n=5, a_{2}=3 \sqrt{2}$ using $a_{2}=a_{1}+(5-1) d$, we have $3 \sqrt{2}=\sqrt{2}+4 d$

$$
\begin{aligned}
& \Rightarrow \quad d=\frac{2 \sqrt{2}}{4}=\frac{\sqrt{2}}{2}=\frac{1}{\sqrt{2}} \\
& \text { Now } \quad A_{1}=a_{1}+d=\sqrt{2}+\frac{1}{\sqrt{2}}=\frac{2+1}{\sqrt{2}}=\frac{3}{\sqrt{2}} \\
& A_{2}=A_{1}+d=\frac{3}{\sqrt{2}}+\frac{1}{\sqrt{2}}=\frac{4}{\sqrt{2}}=2 \sqrt{2} \\
& A_{3}=A_{2}+d=2 \sqrt{2}+\frac{1}{\sqrt{2}}=\frac{4+1}{\sqrt{2}}=\frac{5}{\sqrt{2}}
\end{aligned}
$$

Therefore, $\frac{3}{\sqrt{2}}, 2 \sqrt{2}, \frac{5}{\sqrt{2}}$ are the three A.Ms. between $\sqrt{2}$ and $3 \sqrt{2}$.

# EXERCISE 6.3 

1. Find A.M. between the given numbers:
(i) $2+\sqrt{3} i, 2-\sqrt{3} i$
(ii) $(a+b)^{2},(a-b)^{2}$
2. If $6,11,16$ are three A.Ms. between $a$ and $b$, find $a$ and $b$.
3. Insert five A.Ms. between $\sqrt{2}$ and $\frac{15}{\sqrt{2}}$.
4. The A.M. of two numbers is 7 and their product is 45 . Find the numbers.
5. If $n$ arithmetic means are inserted between $a$ and $b$, prove that $a \geqslant \frac{b-a}{n+1}$, where $d$ is the common difference.
6. If $A$ is the A.M. between $a$ and $b$, prove that $(a-A)^{2}+(A-b)^{2}=\frac{1}{2}(a-b)^{2}$.
7. For what value of $n, \frac{a^{n+1}+b^{n+1}}{a^{n}+b^{n}}$ is the A.M. between $a$ and $b$, where $a \neq b$.

### 6.4 Series

The sum of the terms of a sequence is called the series of the corresponding sequence.
For example, $1+2+3+\cdots+n$ is a finite series of first $n$ natural numbers.
The sum of first $n$ terms of series is denoted by $S_{n}$.
We write, $S_{n}=a_{1}+a_{2}+\cdots+a_{n}$.
Here, $\quad S_{1}=a_{1}$

$$
\begin{aligned}
& S_{2}=a_{1}+a_{2} \\
& S_{3}=a_{1}+a_{2}+a_{3} \\
& S_{n}=a_{1}+a_{2}+a_{3}+\cdots+a_{n} \text { is known as } n^{\text {th }} \text { partial sum. }
\end{aligned}
$$

The sum of the terms of an arithmetic sequence is called an arithmetic series.
To develop a formula for the sum of any arithmetic series, consider

$$
\begin{aligned}
S_{n} & =a_{1}+\left(a_{1}+d\right)+\left(a_{1}+2 d\right)+\cdots+\left(a_{n}-2 d\right)+\left(a_{n}-d\right)+a_{n} \\
S_{n} & =a_{n}+\left(a_{n}-d\right)+\left(a_{n}-2 d\right)+\cdots+\left(a_{1}+2 d\right)+\left(a_{1}+d\right)+a_{1}
\end{aligned}
$$

Thus, $\quad 2 S_{n}=\left(a_{1}+a_{n}\right)+\left(a_{1}+a_{n}\right)+\left(a_{1}+a_{n}\right)+\cdots+\left(a_{1}+a_{n}\right)+\left(a_{1}+a_{n}\right)+\left(a_{1}+a_{n}\right)$

$$
=n\left(a_{1}+a_{n}\right) \quad\left[\text { We have } n \text { terms of }\left(a_{1}+a_{n}\right)\right]
$$

$$
S_{n}=\frac{n}{2}\left(a_{1}+a_{n}\right)
$$

But, $\quad a_{n}=a_{1}+(n-1) d$
Thus, $\quad S_{n}=\frac{n}{2}\left[a_{1}+a_{1}+(n-1) d\right]=\frac{n}{2}\left[2 a_{1}+(n-1) d\right]$

Example 7 Find the sum of the first 100 positive integers.
Solution The series is $1+2+3+\cdots+100$.
Since we can see that $a_{1}=1, a_{n}=100$ and $d=1$.

## Method-1

$$
\begin{aligned}
& S_{n}=\frac{n}{2}\left(a_{1}+a_{n}\right) \\
& S_{100}=\frac{100}{2}(1+100) \\
& S_{100}=50(101) \\
& S_{100}=5050
\end{aligned}
$$

## Method-2

$$
\begin{aligned}
& S_{n}=\frac{n}{2}\left[2 a_{1}+(n-1) d\right] \\
& S_{100}=\frac{100}{2}[2(1)+(100-1) 1] \\
& S_{100}=50(101) \\
& S_{100}=5050
\end{aligned}
$$

Example 8 Find the $19^{\text {th }}$ term and the partial sum of 19 terms of the arithmetic series:

$$
2+\frac{7}{2}+5+\frac{13}{2}+\cdots
$$

Solution Here, $a_{1}=2, a_{2}=\frac{7}{2}$ and $d=a_{2}=a_{1}=\frac{7}{2}-2=\frac{3}{2}$
Using $\quad a_{n}=a_{1}+(n-1) d$
Substitute $n=19$

$$
\begin{aligned}
& a_{19}=2+(19-1) \frac{3}{2} \\
& 2+18\left(\frac{3}{2}\right)=2+27=29
\end{aligned}
$$

Using $\quad S_{n}=\frac{n}{2}\left(a_{1}+a_{n}\right)$

$$
S_{19}=\frac{19}{2}\left(a_{1}+a_{19}\right)
$$

$$
S_{19}=\frac{19}{2}(2+29)=\frac{19}{2}(31)=\frac{589}{2}
$$

Example 9 Find the arithmetic series if its fifth term is 19 and $S_{4}=a_{9}+1$.
Solution Given that $a_{5}=19$, that is,

$$
a_{1}+4 d=19
$$

Using the other given condition, we have

$$
S_{4}=\frac{4}{2}\left[2 a_{1}+(4-1) d\right]=a_{9}+1
$$

$$
\begin{aligned}
4 a_{1}+6 d & =a_{1}+8 d+1 \\
3 a_{1}-1 & =2 d
\end{aligned}
$$

Substituting $2 d=3 a_{1}-1$ in (i), we have

$$
\begin{aligned}
a_{1}+2\left(3 a_{1}-1\right) & =19 \\
7 a_{1}=21 & \Rightarrow a_{1}=3
\end{aligned}
$$

From (i), we have,

$$
\begin{aligned}
4 d & =19-a_{1}=19-3=16 \\
\Rightarrow \quad d & =4
\end{aligned}
$$

Thus, the series is $3+7+11+\cdots$.
Example10 How many terms of the series $-9-6-3+0+\ldots$ amount to 66 ?
Solution Here, $a_{1}=-9$ and $d=-6-(-9)=3$.

$$
\text { Let } S_{n}=66
$$

Using $S_{n}=\frac{n}{2}\left[2 a_{1}+(n-1) d\right]$, we have

$$
\begin{aligned}
& 66=\frac{n}{2}[2(-9)+(n-1) 3] \\
& 132=n[3 n-21] \Rightarrow 132=3 n(n-7) \Rightarrow 44=n(n-7) \\
& n^{2}-7 n-44=0 \\
& \Rightarrow \quad n=\frac{7 \pm \sqrt{49+176}}{2} \\
& =\frac{7 \pm \sqrt{225}}{2}=\frac{7 \pm 15}{2} \Rightarrow n=11,-4
\end{aligned}
$$

But $n$ cannot be negative in this case, so $n=11$, that is, the sum of eleven terms is 66 .
Example11 Find the first three terms of an arithmetic series in which $a_{1}=9, a_{n}=105$ and $S_{n}=741$.
Solution Step - I: Since we know $a_{1}, a_{n}$ and $S_{n}$,
We use $S_{n}=\frac{n}{2}\left(a_{1}+a_{n}\right)$ to find $n$.

$$
741=\frac{n}{2}(9+105)
$$

$$
741=57 n
$$

$$
13=n
$$

Step - II: Find $d$.

$$
\begin{aligned}
& a_{n}=a_{1}+(n-1) d \\
& 105=9+(13-1) d \\
& 96=12 d \\
& 8=d
\end{aligned}
$$

Step - III: Use $d$ to determine $a_{2}$ and $a_{3}$.

$$
a_{2}=9+8=17, \quad a_{3}=17+8=25
$$

The first three terms are 9,17 and 25 .

# EXERCISE 6.4 

1. Sum the series:
(i) $3+6+9+\cdots+a_{20}$
(ii) $\frac{4}{\sqrt{5}}+\sqrt{5}+\frac{6}{\sqrt{5}}+\cdots+a_{n}$
2. Find $S_{n}$ for each arithmetic series:
(i) $a_{1}=4, n=25, a_{n}=100$
(ii) $a_{1}=40, n=20, d=-1$
(iii) $a_{n}=52, n=21, d=-4$
3. Find $a_{1}$ for the arithmetic series: $d=8, n=19, S_{n}=1786$.
4. How many terms of the series: $96+93+90+\sim$ amount to 1071.
5. If the three sides of a right-angled triangle having perimeter 36 cm are in A.P., find them.
6. Sum the series
(i) $3+5-7+9+11-13+15+17-19+\cdots$ to $3 n$ terms.
(ii) $1+4-7+10+13-16+19+22-25+\cdots$ to $3 n$ terms.
7. Find the sum of 20 terms of the series whose $r^{\text {th }}$ term is $3 r+1$.
8. The $5^{\text {th }}$ and $9^{\text {th }}$ term of an A.P. are 11 and 17 respectively. Find the sum of 20 terms.
9. Obtain the sum of all integers in the first 1000 positive integers which are neither divisible by 5 nor by 2 .
10. The sum of 9 terms of an A.P. is 171 and its eighth term is 31 . Find the series.
11. The $5^{\text {th }}$ term of an arithmetic progression is 21 and the sum of first six terms is 90 . Find the $18^{\text {th }}$ term.
12. The sum of three numbers in an A.P. is 24 and their product is 440 . Find the numbers.
13. The first four terms of an A.P. are $2,6,10$ and 14 . Find the least number of terms needed so that the sum of the terms is greater than 2000.
14. Find four numbers in A.P. whose sum is 32 and the sum of whose squares is 276.
15. Find the five numbers in A.P. whose sum is 25 and the sum of whose squares is 135 .
16. If $\frac{1}{a+b} \cdot \frac{1}{c+a} \cdot \frac{1}{b+c}$ are in A.P. then show that $a^{2}, b^{2}, c^{2}$ are in A.P.

17. The sum of the first four terms of an A.P. is 56 . The sum of the last four terms is 112. If its first term is 11 , then find number of terms.
18. The first, second and last terms of an A.P. are $a, b$ and $c$ respectively. Show that the sum of A.P. is $\frac{(b+c-2 a)(c+a)}{2(b-a)}$.
19. Show that the sum of $n$ A.Ms. between $a$ and $b$ is $n$ times the single A.M. between them.

# 6.5 Geometric Progression (G.P.) 

A geometric progression or geometric sequence is a sequence fixed in which each term after the first is found by multiplying the previous term by a non-zero constant $r$ called common ratio.
Like arithmetic progression, we can label the terms of a geometric sequence as $a_{1}, a_{2}, a_{3}$ and so on, $a_{1} \neq 0$. The $n^{\text {th }}$ term is $a_{n}$ and the previous term is $a_{n-1}$. So, $a_{n}=r\left(a_{n-1}\right)$. Thus, $r=\frac{a_{n}}{a_{n-1}}$. That is, the common ratio can be found by dividing any term by its previous term.

### 6.5.1 Rule for $n$th term of a G.P.

Each term after the first term is an $r$ multiple of its preceding term. Thus, we have,

$$
\begin{aligned}
& a_{2}=a_{1} r=a_{1} r^{2-1} \\
& a_{3}=a_{2} r=\left(a_{1} r\right) r=a_{1} r^{2}=a_{1} r^{3-1} \\
& a_{4}=a_{2} r=\left(a_{1} r^{2}\right) r=a_{1} r^{3}=a_{1} r^{4-1} \\
& \vdots \\
& a_{n}=a_{1} r^{n-1} \text { which is the general term of a G.P. }
\end{aligned}
$$

### 6.5.2 Properties of G.P.

(i) If each term of a G.P. is multiplied or divided by the same non-zero number, then the resulting sequence is also a G.P. that is if $g_{1}, g_{2}, g_{3}, \ldots, g_{n}, \ldots$ are in G.P. and $k$ is a non-zero number, then
(a) $k g_{1}, k g_{2}, k g_{3}, \ldots, k g_{n}, \ldots$ are also in G.P.
(b) $\frac{g_{1}}{k}, \frac{g_{2}}{k}, \frac{g_{3}}{k}, \ldots, \frac{g_{n}}{k}, \ldots$ are also in G.P.
(ii) The reciprocals of the term of a G.P. also form a G.P. that is if $a, b, c$ are in G.P., then $\frac{1}{a}, \frac{1}{b}, \frac{1}{c}$ are also in G.P.

(iii) If each term of a G.P. is raised to the same power, the resulting numbers also form a G.P. that is, if $a, b, c$ are in G.P., then $a^{n}, b^{n}, c^{n}$ are also in G.P.
(iv) Three numbers $a, b, c$ are in G.P. if and only if $b^{2}=a c$.
(v) If the set of positive numbers $a_{1}, a_{2}, a_{3}, \ldots, a_{n}, \ldots$ are in G.P., then $\log a_{1}, \log a_{2}$, $\log a_{3}, \ldots, \log a_{n}, \ldots$ are in A.P. and vice-versa.
(vi) Term by term multiplication or division of two G.Ps. are again in G.P. i.e., if $a_{1}, a_{2}, a_{3} \ldots, a_{n}$, and $b_{1}, b_{2}, b_{3}, \ldots, b_{n}$, are in G.P. then $a_{1} b_{1}, a_{2} b_{2}, a_{3} b_{3}, \ldots$, $a_{n} b_{n}$ and $\frac{a_{1}}{b_{1}}, \frac{a_{2}}{b_{2}}, \frac{a_{3}}{b_{3}}, \ldots, \frac{a_{n}}{b_{n}}$ are also in G.P.
Example 12 Find the eighth term of a geometric sequence for which $a_{1}=-3$ and $r=-2$.
Solution Here, $a_{1}=-3, r=-2, n=8$

$$
\begin{aligned}
& a_{n}=a_{1} \cdot r^{n-1} \\
& a_{8}=(-3) \cdot(-2)^{8-1} \\
& a_{8}=(-3) \cdot(-128) \\
& a_{8}=384
\end{aligned}
$$

Example 13 Find the $n^{\text {th }}$ term of the G.P., 3, 12, 48, ...
Solution Here $a_{1}=3, r=4$

$$
\begin{aligned}
& a_{n}=a_{1} \cdot r^{n-1} \\
& a_{n}=3 \cdot 4^{n-1}
\end{aligned}
$$

Example 14 Find the tenth term of the G.P., for which $a_{4}=108$ and $r=3$.
Solution Step - 1: Find $a_{1}$.
Here, $n=4, r=3, a_{4}=108$

$$
\begin{aligned}
a_{n} & =a_{1} \cdot r^{n-1} \\
a_{4} & =a_{1} \cdot 3^{4-1} \\
108 & =27 a_{1} \\
4 & =a_{1} \\
a_{1} & =4
\end{aligned}
$$

Step - 2: Find $a_{10}$.
Here, $n=10, a_{1}=4, r=3$

$$
\begin{aligned}
& a_{n}=a_{1} \cdot r^{n-1} \\
& a_{10}=4 \cdot 3^{10-1} \\
& a_{10}=78,732
\end{aligned}
$$

Example 15 Find the $5^{\text {th }}$ term of the G.P., 3, 6, 12, ....
Solution Here $a_{1}=3, a_{2}=6$, therefore, $r=\frac{a_{2}}{a_{1}}=\frac{6}{3}=2$.

Using $a_{n}=a_{1} r^{n-1}$ for $n=5$, we have

$$
a_{5}=a_{1} r^{5-1}=3 \cdot 2^{5-1}=3 \cdot 2^{4}=48
$$

Example16 Find $a_{n}$ if $a_{4}=\frac{8}{27}$ and $a_{7}=\frac{-64}{729}$ of a G.P.
Solution: To find $a_{n}$ we have to find $a_{1}$ and $r$.

Using $\quad a_{n}=a_{1} r^{n-1}$

$$
a_{4}=a_{1} r^{4-1}=a_{1} r^{3}, \text { so } a_{1} r^{3}=\frac{8}{27}
$$

and $\quad a_{7}=a_{1} r^{7-1}=a_{1} r^{6}$, so $a_{1} r^{6}=\frac{-64}{729}$
(iii)

Thus, $\quad \frac{a_{1} r^{6}}{a_{1} r^{3}}=\frac{\frac{-64}{729}}{\frac{8}{27}}=\frac{-8}{27} \quad$ or $\quad r^{3}=\left(\frac{-2}{3}\right)^{3}$
$\Rightarrow \quad r=-\frac{2}{3}$
(taking only real value of $r$ )
Put $r^{3}=-\frac{8}{27}$ in (ii), to obtain $a_{1}$ that is,

$$
a_{1}\left(-\frac{8}{27}\right)=\frac{8}{27} \Rightarrow a_{1}=-1
$$

Now putting $a_{1}=-1$ and $r=\frac{-2}{3}$ in (i), we get

$$
a_{4}=(-1)\left(-\frac{2}{3}\right)^{n-1}=(-1)(-1)^{n-1} \cdot\left(\frac{2}{3}\right)^{n-1}=(-1)^{n}\left(\frac{2}{3}\right)^{n-1}
$$

# EXERCISE 6.5 

1. Find the $6^{\text {th }}$ term of the G.P.: $-6,-3, \frac{-3}{2}, \cdots$.
2. Find the $8^{\text {th }}$ term of the sequence, $3,3^{2}, 3^{3}, \cdots$.
3. The $n^{\text {th }}$ terms of the sequences $1,2,4,8, \cdots$ and $256,128,64, \cdots$ are equal. Find the value of $n$.
4. Find the first five terms of each sequence described:
(i) $a_{1}=243, r=\frac{1}{3}$
(ii) $a_{1}=579, r=-\frac{1}{2}$

5. Find the $12^{\text {th }}$ term of $1+i, 2 i,-2+2 i, \cdots$.
6. If the $4^{\text {th }}$ and $9^{\text {th }}$ terms of a G.P. are 54 and 13122 respectively. Find the G.P. Also find its general term.
7. If $a, b, c, d$ are in G.P., prove that:
(i) $a-b, b-c, c-d$ are in G.P.
(ii) $a^{2}-b^{2}, b^{2}-c^{2}, c^{2}-d^{2}$ are in G.P.
(iii) $a^{2}+b^{2}, b^{2}+c^{2}, c^{2}+d^{2}$ are in G.P.
8. If $(p+q)^{\text {th }}$ term of a G.P. is $m$ and $(p-q)^{\text {th }}$ term is $n$, then find the $p^{\text {th }}$ term.
9. Find three consecutive numbers in G.P. whose sum is 26 and their product is 216.
10. The $3^{\text {rd }}$ term of a G.P. is the square of $1^{\text {st }}$ term. If the $2^{\text {nd }}$ term is 9 then find the $6^{\text {th }}$ term.
11. If $\frac{1}{a}, \frac{1}{b}$ and $\frac{1}{c}$ are in G.P. Show that the common ratio is $\pm \sqrt{\frac{a}{c}}$.
12. If the numbers 1,4 and 3 are subtracted from three consecutive terms of an A.P., the resulting numbers are in G.P. Find the original numbers if their sum is 21.
13. If three consecutive numbers in A.P. are increased by $1,4,15$ respectively, the resulting numbers are in G.P. Find the original numbers if their sum is 6 .
14. If $p^{\text {th }}, q^{\text {th }}$ terms of a G.P. are $q$ and $p$ respectively, show that $(p+q)^{\text {th }}$ term is $\left(q^{p}+p^{q}\right)^{\frac{1}{p-1}}$.
15. If $a, 2 a+2,3 a+3, \ldots$ are in G.P., then find the fifth term.

# 6.6 Geometric Mean (G.M.) 

A number $G$ is said to be a geometric mean (G.M.) between two numbers $a$ and $b$ if $a$, $G, b$ are in G.P. Therefore

$$
\begin{aligned}
& \frac{G}{a}=\frac{b}{G} \\
& \Rightarrow \quad G^{2}=a b \\
& \Rightarrow \quad G= \pm \sqrt{a b}
\end{aligned} \quad \text { Note } G_{1}, G_{2}, G_{3}, \ldots, G_{a} \text { are said to be } n
$$

G.Ms. between two numbers $a$ and $b$ if $a$, $G_{1}, G_{2}, G_{3}, \ldots, G_{a}, b$ are in G.P.

Example17 Insert three G.Ms. between 2 and $\frac{1}{2}$.
Solution Let $G_{1}, G_{2}, G_{3}$ be three G.Ms. between 2 and $\frac{1}{2}$. Therefore

$2, G_{1}, G_{2}, G_{3}, \frac{1}{2}$ are in G.P. Here $a_{1}=2, a_{2}=\frac{1}{2}$ and $n=5$.
Using $a_{n}=a_{1} r^{n-1}$ we have

$$
a_{2}=a_{1} r^{2-1} \text { that is, } a_{2}=a_{1} r^{4}
$$

Now substituting the values of $a_{2}$ and $a_{1}$ in (i) we have

$$
\frac{1}{2}=2 r^{4} \quad \text { or } \quad r^{4}=\frac{1}{4}
$$

Taking square root of (ii), we get

$$
r^{2}= \pm \frac{1}{2}
$$

We have, $r^{2}=\frac{1}{2} \quad$ or $\quad r^{2}=-\frac{1}{2}=\frac{i^{2}}{2}\left(\because-1=i^{1}\right)$
$\Rightarrow \quad r= \pm \frac{1}{\sqrt{2}} \quad$ or $\quad r= \pm \frac{1}{\sqrt{2}} i$
When $\quad r=\frac{1}{\sqrt{2}}$, then $G_{1}=2\left(\frac{1}{\sqrt{2}}\right)=\sqrt{2}, G_{2}=2\left(\frac{1}{\sqrt{2}}\right)^{2}=1, \quad G_{3}=2\left(\frac{1}{\sqrt{2}}\right)^{2}=\frac{1}{\sqrt{2}}$
When $\quad r=\frac{-1}{\sqrt{2}}$, then $G_{1}=2\left(\frac{-1}{\sqrt{2}}\right)=-\sqrt{2}, G_{2}=2\left(\frac{-1}{\sqrt{2}}\right)^{2}=1, \quad G_{3}=2\left(\frac{-1}{\sqrt{2}}\right)^{2}=-\frac{1}{\sqrt{2}}$
When $\quad r=\frac{i}{\sqrt{2}}$, then $G_{1}=2\left(\frac{i}{\sqrt{2}}\right)=\sqrt{2} i, G_{2}=2\left(\frac{i}{\sqrt{2}}\right)^{2}=-1, G_{3}=2\left(\frac{i}{\sqrt{2}}\right)^{2}=-\frac{i}{\sqrt{2}}$
When $\quad r=\frac{-i}{\sqrt{2}}$, then $G_{1}=2\left(\frac{-i}{\sqrt{2}}\right)=-\sqrt{2} i, G_{2}=2\left(\frac{-i}{\sqrt{2}}\right)^{2}=-1, G_{3}=2\left(\frac{-i}{\sqrt{2}}\right)^{2}=\frac{i}{\sqrt{2}}$
Note The real values of $r$ are usually taken but here other cases are considered to widen the outlook of the students.

# EXERCISE 6.6 

1. Find G.M. between:
(i) -2 and 8
(ii) $-2 i$ and $8 i$
(iii) 6 and 9
2. Insert four real geometric means between 3 and 96 .
3. If both $x$ and $y$ are positive distinct real numbers, show that the geometric mean between $x$ and $y$ is less than their arithmetic mean.
4. For what value of $n, \frac{a^{n}+b^{n}}{a^{n-1}+b^{n-1}}$ is the positive geometric mean between $a$ and $b$ ?

5. The A.M. of two positive integral numbers exceeds their (positive) G.M. by 2 and their sum is 20 , find the numbers.
6. The A.M. between two numbers is 5 and their (positive) G.M. is 4 . Find the numbers.
7. The arithmetic mean between two positive numbers $a$ and $b$ is double their geometric mean. Prove that $a: b=2+\sqrt{3}: 2-\sqrt{3}$.
8. If one geometric mean $G$ and two arithmetic means $p$ and $q$ are inserted between two positive numbers, show that $G^{2}=(2 p-q)(2 q-p)$.

# 6.7 Geometric Series 

Suppose you e-mail an Islamic quote to three friends on Monday. Each of those friends send it to three of their friends on Tuesday. Each person who receives the quote on Tuesday sends it to three more people on Wednesday and so on.
[Image removed]

Notice that every day, the number of people who read your Islamic quote is three times the number that read it the day before. By Sunday, the number of people, including yourself, who have read the quote is $1+3+9+27+81+243+729+2187$ or 3280 . The numbers $1,3,9,27,81,243,729$ and 2187 form a geometric sequence in which $a_{1}=1$ and $r=3$. The indicated sum of the numbers in the sequence, $1+3+9+27+$ $81+243+729+2187$ is called a geometric series.

The sum of a geometric progression can be written as: $S_{n}=\frac{a_{1}\left(1-r^{n}\right)}{1-r}, r \neq 1$
To develop a formula for the sum of a geometric series, consider

$$
\begin{aligned}
& S_{n}=a_{1}+a_{1} r+a_{1} r^{2}+\cdots+a_{1} r^{n-3}+a_{1} r^{n-2}+a_{1} r^{n-1} \\
& r S_{n}=a_{1} r+a_{1} r^{2}+\cdots+a_{1} r^{n-3}+a_{1} r^{n-2}+a_{1} r^{n-1}+a_{1} r^{n}
\end{aligned}
$$

Subtracting (ii) from (i), we get

$$
S_{n}-r S_{n}=a_{1}-a_{1} r^{n}
$$

Note
If $r=1$, then $S_{n}=n a$.

$$
\begin{aligned}
S_{n}(1-r) & =a_{1}\left(1-r^{n}\right) \\
S_{n} & =\frac{a_{1}\left(1-r^{n}\right)}{1-r}, r \neq 1
\end{aligned}
$$

Example 18 Find the sum of $n$ terms of the geometric series if $a_{n}=(-3)\left(\frac{2}{5}\right)^{n}$.
Solution We can write $(-3)\left(\frac{2}{5}\right)^{n}$ as:

$$
-3\left(\frac{2}{5}\right)\left(\frac{2}{5}\right)^{n-1}=\left(-\frac{6}{5}\right)\left(\frac{2}{5}\right)^{n-1}, \text { that is } a_{n}=\left(-\frac{6}{5}\right)\left(\frac{2}{5}\right)^{n-1}
$$

comparing $\left(-\frac{6}{5}\right)\left(\frac{2}{5}\right)^{n-1}$ with $a_{1} r^{n-1}$, we have $a_{1}=-\frac{6}{5}$ and $r=\frac{2}{5}$
Thus, $\quad S_{n}=\frac{a_{1}\left(1-r^{n}\right)}{1-r}=\frac{-\frac{6}{5}\left[1-\left(\frac{2}{5}\right)^{n}\right]}{1-\frac{2}{5}}$

$$
=\left(-\frac{6}{5}\right)\left(\frac{5}{3}\right)\left[1-\left(\frac{2}{5}\right)^{n}\right]=(-2)\left[1-\left(\frac{2}{5}\right)^{n}\right]
$$

# EXERCISE 6.7 

1. Find the sum of first 15 terms of the G.P., $1, \frac{1}{3}, \frac{1}{9}, \cdots$.
2. The $3^{\text {rd }}$ term of a G.P. is 16 and the $6^{\text {th }}$ term is -128 . Find the first term and the sum of the first seven terms.
3. Sum to $n$ terms the series:
(i) $0.2+0.22+0.222+\cdots$
(ii) $3+33+333+\cdots$
4. Sum to $n$ terms the series:
(i) $1+(a+b)+\left(a^{2}+a b+b^{2}\right)+\left(a^{3}+a^{2} b+a b^{2}+b^{3}\right)+\cdots$
(ii) $r+(1+k) r^{2}+\left(1+k+k^{2}\right) r^{3}+\cdots$
5. Sum the series $2+(1-i)+\binom{1}{i}+\cdots$ to 8 terms.
6. Show that the ratio of the sum of first $n$ terms of a G.P. to the sum of terms from $(n+1)^{\text {th }}$ to $(2 n)^{\text {th }}$ term is $\frac{1}{r^{n}}$, where $r$ is the common ratio of the G.P.

# 6.8 Arithmetico-Geometric Progression (A.G.P.) 

Suppose $a_{1}, a_{2}, a_{3}, \ldots, a_{n}, \ldots$ is an A.P., and $b_{1}, b_{2}, b_{3}, \ldots, b_{n}, \ldots$ is a G.P. then the sequence formed by multiplying the corresponding terms of A.P. and G.P., that is, $a_{1} b_{1}$, $a_{2} b_{2}, a_{3} b_{3}, \ldots, a_{n} b_{n}, \ldots$ is said to be an arithmetico-geometric sequence.
Consider an A.P., $a, a+d, a+2 d, \ldots,\{a+(n-1) d\}$ and a G.P., $b, b r, b r^{2}, \ldots, b r^{n-1}$ where $r \neq 1$.
Multiplying the corresponding terms of A.P. and G.P., we get an arithmeticogeometric sequence

$$
a b,(a+d) b r,(a+2 d) b r^{2}, \ldots,\{a+(n-1) d\} b r^{n-1}
$$

Note that the $n^{\text {th }}$ term of arithmetico-geometric sequence is product of $n^{\text {th }}$ term of A.P. and $n^{\text {th }}$ term of G.P.

### 6.8.1 Arithmetico-Geometric Series

Sum of the terms of arithmetico-geometric sequence is called arithmetico-geometric series. Thus, arithmetico-geometric series has the form

$$
a b+(a+d) b r+(a+2 d) b r^{2}+\cdots+\{a+(n-1) d\} b r^{n-1}
$$

Sum of first $n$ Terms of Arithmetico-Gemetric Series
Let $\quad S_{n}=a b+(a+d) b r+(a+2 d) b r^{2}+\cdots+[a+(n-1) d] b r^{n-1}$
Then $r S_{n}=\quad a b r+(a+d) b r^{2}+\cdots+[a+(n-2) d] b r^{n-1}+[a+(n-1) d] b r^{n} \quad$ (ii)
Subtracting (ii) from (i), we get

$$
\begin{aligned}
(1-r) S_{n} & =a b+\left[d b r+d b r^{2}+\cdots+d b r^{n-1}\right]-[a+(n-1) d] b r^{n} \\
& =a b+\frac{d b r\left(1-r^{n-1}\right)}{1-r}-[a+(n-1) d] b r^{n} \\
& =a b+\frac{d b r}{1-r}-\frac{d b r^{n}}{1-r}-[a+(n-1) d] b r^{n} \\
S_{n} & =\frac{a b}{1-r}+\frac{d b r}{(1-r)^{2}}-\frac{d b r^{n}}{(1-r)^{2}}-\frac{[a+(n-1) d] b r^{n}}{1-r}
\end{aligned}
$$

which is the sum of the $n$ terms of arithmetico-geometric series.

### 6.8.2 Sum to Infinity of Arithmetico-Geometric Series

If $|r|<1$, then $r^{n} \rightarrow 0$ and $n r^{n} \rightarrow 0$ as $n \rightarrow \infty$
Therefore, (iii) reduces to $S_{\infty}=\frac{a b}{1-r}+\frac{d b r}{(1-r)^{2}}$
which is the sum to infinity of arithmetico-geometric series.

Example 19 Sum the series upto $n$ terms: $2 \cdot 1+3 \cdot 2+4 \cdot 4+5 \cdot 8+\cdots$
Solution Let $S_{n}=2 \cdot 1+3 \cdot 2+4 \cdot 2^{2}+5 \cdot 2^{3}+\cdots$ to $n$ terms
$n^{\text {th }}$ term of the A.P., $2,3,4,5, \cdots$ is $a_{1}+(n-1) d=2+(n-1)(1)$

$$
=2+n-1=n+1
$$

$n^{\text {th }}$ term of the G.P., $1,2,2^{2}, 2^{3}, \cdots$ is $a_{1} r^{n-1}=1 \cdot 2^{n-1}=2^{n-1}$
So, $\quad S_{n}=2 \cdot 1+3 \cdot 2+4 \cdot 2^{2}+5 \cdot 2^{3}+\cdots+(n+1) 2^{n-1}$
Multiplying both sides by common ratio of G.P., we get

$$
2 S_{n}=\quad 2 \cdot 2+3 \cdot 2^{2}+4 \cdot 2^{3}+5 \cdot 2^{4}+\cdots+(n) 2^{n-1}+(n+1) 2^{n}
$$

Subtracting (ii) from (i), we get

$$
\begin{aligned}
S_{n}-2 S_{n} & =2 \cdot 1+(3-2) \cdot 2+(4-3) \cdot 2^{2}+(5-4) \cdot 2^{3}+\cdots+(n+1-n) 2^{n-1}-(n+1) 2^{n} \\
-S_{n} & =2 \cdot 1+1 \cdot 2+1 \cdot 2^{2}+1 \cdot 2^{3}+\cdots+1 \cdot 2^{n-1}-(n+1) 2^{n} \\
-S_{n} & =2+\left\{2+2^{2}+2^{3}+\cdots+2^{n-1}\right\}-(n+1) 2^{n} \\
-S_{n} & =2+\frac{2\left(2^{n-1}-1\right)}{2-1}-(n+1) \cdot 2^{n} \\
-S_{n} & =2+2^{n}-2-n \cdot 2^{n}-2^{n} \\
-S_{n} & =-n \cdot 2^{n} \\
S_{n} & =n \cdot 2^{n}
\end{aligned}
$$

Example 20 Sum the series upto $n$ terms: $2+\frac{4}{3}+\frac{6}{9}+\frac{8}{27}+\cdots$
Solution Let $S_{n}=2+\frac{4}{3}+\frac{6}{9}+\frac{8}{27}+\cdots$ to $n$ terms
$n^{\text {th }}$ term of the A.P., $2,4,6,8, \ldots$ is $2+(n-1)(2)$

$$
=2+2 n-2=2 n
$$

$n^{\text {th }}$ term of the G.P., $1, \frac{1}{3}, \frac{1}{9}, \frac{1}{27}, \cdots$ is $(1)\left(\frac{1}{3}\right)^{-1}=\frac{1}{3^{n-1}}$
So, $\quad S_{n}=2+\frac{4}{3}+\frac{6}{9}+\frac{8}{27}+\cdots+\frac{2 n}{3^{n-1}}$

$$
\frac{1}{3} S_{n}=\frac{2}{3}+\frac{4}{9}+\frac{6}{27}+\cdots+\frac{2 n-2}{3^{n-1}}+\frac{2 n}{3^{n}}
$$

Subtracting (ii) from (i), we get

$$
\begin{aligned}
& \left(1-\frac{1}{3}\right) S_{n}=2+\frac{4-2}{3}+\frac{6-4}{9}+\frac{8-6}{27}+\cdots+\frac{2 n-2 n+2}{3^{n-1}}-\frac{2 n}{3^{n}} \\
& \frac{2}{3} S_{n}=2+\left[\frac{2}{3}+\frac{2}{9}+\frac{2}{27}+\cdots+\frac{2}{3^{n-1}}\right]-\frac{2 n}{3^{n}} \\
& \frac{2}{3} S_{n}=2+\left[\frac{\frac{2}{3}\left\{1-\left(\frac{1}{3}\right)^{n-1}\right\}}{1-\frac{1}{3}}\right]-\frac{2 n}{3^{n}} \\
& =2+\frac{\frac{2}{3}\left\{1-\left(\frac{1}{3}\right)^{n-1}\right\}}{\frac{2}{3}}-\frac{2 n}{3^{n}} \\
& =2+1-\left(\frac{1}{3}\right)^{n-1}-2 n\left(\frac{1}{3}\right)^{n} \\
& \frac{2}{3} S_{n}=3-\left(\frac{1}{3}\right)^{n-1}-2 n\left(\frac{1}{3}\right)^{n} \\
& S_{n}=\frac{9}{2}-\frac{3}{2}\left(\frac{1}{3}\right)^{n-1}-3 n\left(\frac{1}{3}\right)^{n}
\end{aligned}
$$

Example 21 Find the sum to $n$ terms of the series: $1+2 x+3 x^{2}+4 x^{3}+\ldots$ where $x \neq 1$. If $|x|<1$, sum the series to infinity.
Solution Let $S_{n}=1+2 x+3 x^{2}+4 x^{3}+\cdots+n x^{n-1}$

$$
\therefore \quad x S_{n}=\quad x+2 x^{2}+3 x^{3}+\cdots+(n-1) x^{n-1}+n x^{n}
$$

Subtracting (ii) from (i), we get

$$
\begin{aligned}
(1-x) S_{n} & =1+x+x^{2}+x^{3}+\cdots+x^{n-1}-n x^{n} \\
& =\frac{1\left(1-x^{n}\right)}{1-x}-n x^{n} \\
& =\frac{1-x^{n}-n(1-x) x^{n}}{1-x}
\end{aligned}
$$

$$
\begin{aligned}
& =\frac{1-x^{n}-n x^{n}+n x^{n+1}}{1-x} \\
(1-x) S_{n} & =\frac{1-(n+1) x^{n}+n x^{n+1}}{1-x} \\
S_{n} & =\frac{1-(n+1) x^{n}+n x^{n+1}}{(1-x)^{2}}
\end{aligned}
$$

If $|x|<1$, then $x^{n} \rightarrow 0, n x^{n} \rightarrow 0$ as $n \rightarrow \infty$

$$
\therefore \quad S_{\infty}=\frac{1}{(1-x)^{2}}
$$

# EXERCISE 6.8 

1. Find the $8^{\text {th }}$ term of the arithmetico-geometric sequence, where the arithmetic part is $1,4,7, \ldots$ and the geometric part is $5,10,20$.
2. Find the $n^{\text {th }}$ term of the arithmetico-geometric sequence, where the arithmetic part is $3,7,11, \ldots$ and the geometric part is $3,6,18, \cdots$.
3. Consider the arithmetico-geometric sequence defined by arithmetic part:
$a_{n+1}=2 n+5$ and geometric part $b_{n-2}=\frac{1}{9}(-3)^{n}$. Find the $n^{\text {th }}$ term and the sum of first three terms of the arithmetico-geometric sequence.
4. Sum to $n$ terms the following series:
(i) $1 \cdot 2+3 \cdot 4 \pm 5 \cdot 8+7 \cdot 16+\cdots$
(ii) $2 \cdot 3+4 \cdot 3^{2}+6 \cdot 3^{3}+8 \cdot 3^{4}+\ldots$
(iii) $2+\frac{5}{4}+\frac{8}{4^{2}}+\frac{11}{4^{3}}+\cdots$
(iv) $1+\frac{3}{5}+\frac{5}{5^{2}}+\frac{7}{5^{3}}+\cdots$
(v) $1+\frac{4}{3}+\frac{7}{9}+\frac{10}{27}+\cdots$
5. Sum the following infinite series:
(i) $1+\frac{3}{2}+\frac{5}{4}+\frac{7}{8}+\cdots$
(ii) $2+\frac{5}{3}+\frac{8}{9}+\frac{11}{27}+\cdots$
6. Show that $2^{\frac{1}{2}} \cdot 4^{\frac{1}{4}} \cdot 8^{\frac{1}{8}} \cdot 16^{\frac{1}{16}} \cdots \infty=4$
7. Show that $\sqrt{4} \cdot \sqrt[4]{16} \cdot \sqrt[8]{64} \cdot \sqrt[10]{256} \cdots \infty=16$

8. Sum to $n$ terms the series $2+4 x+6 x^{2}+8 x^{3}+\cdots$ where $x \neq 1$
9. Find the sum to $n$ terms of the series: $\frac{2 n+1}{2 n-1}+3\left(\frac{2 n+1}{2 n-1}\right)^{2}+5\left(\frac{2 n+1}{2 n-1}\right)^{3}+\cdots$
10. Prove that $1+2\left(1+\frac{1}{n}\right)+3\left(1+\frac{1}{n}\right)^{2}+\cdots$ to $n$ terms $=n^{2}$
11. Sum the series to $n$ terms $2+5 x+8 x^{2}+11 x^{3}+\cdots$ and deduce the sum to infinity if $|x|<1$.

# 6.9 Harmonic Progression (H.P.) 

A sequence of numbers is called a Harmonic Sequence or Harmonic Progression if the reciprocals of its terms are in arithmetic progression. The sequence $1, \frac{1}{3}, \frac{1}{5}, \frac{1}{7}$ is a harmonic sequence since their reciprocals $1,3,5,7$ are in A.P.
Remember that the reciprocal of zero is not defined, so zero cannot be the term of a harmonic sequence.

The general form of the harmonic sequence is $\frac{1}{a_{1}}, \frac{1}{a_{1}+d}, \frac{1}{a_{1}+2 d}, \cdots, \frac{1}{a_{1}+(n-1) d}$.
Example 22 Find the $n^{\text {th }}$ and $8^{\text {th }}$ terms of H.P. : $\frac{1}{2}, \frac{1}{5}, \frac{1}{8}, \cdots$
Solution The reciprocals of the terms of the sequence,

$$
\frac{1}{2}, \frac{1}{5}, \frac{1}{8}, \cdots \quad \text { are } 2,5,8, \cdots
$$

The numbers $2,5,8, \cdots$ are in A.P., so

$$
a_{1}=2 \text { and } d=5-2=3
$$

Putting these values in $a_{n}=a_{1}+(n-1) d$, we have

$$
\begin{aligned}
a_{n} & =2+(n-1) 3 \\
& =3 n-1
\end{aligned}
$$

Thus, the $n^{\text {th }}$ term of the given sequence $=\frac{1}{a_{n}}=\frac{1}{3 n-1}$ and substituting $n=8$ in $\frac{1}{3 n-1}$,

we get the $8^{\text {th }}$ term of the given H.P. which is $\frac{1}{3 \times 8-1}=\frac{1}{23}$.
Alternatively, $a_{8}$ of the A.P. $=a_{1}+(8-\mathrm{I}) d$

$$
\begin{aligned}
& =2+7(3) \\
& =23
\end{aligned}
$$

Thus, the $8^{\text {th }}$ term of the given H.P. $=\frac{1}{23}$
Example 23 If the $4^{\text {th }}$ and $7^{\text {th }}$ terms of the H.P. are $\frac{2}{13}$ and $\frac{2}{25}$ respectively, find the sequence.
Solution Since the $4^{\text {th }}$ term of the H.P. $=\frac{2}{13}$ and its $7^{\text {th }}$ term $=\frac{2}{25}$, therefore the $4^{\text {th }}$ and $7^{\text {th }}$ terms of the corresponding A.P. are $\frac{13}{2}$ and $\frac{25}{2}$ respectively.
Now taking $a_{1}$, the first term and $d$, the common difference of the corresponding A.P., we have,

$$
a_{1}+3 d=\frac{13}{2}
$$

and $\quad a_{1}+6 d=\frac{25}{2}$
Subtracting (i) from (ii), gives

$$
3 d=\frac{25}{2}-\frac{13}{2}=6 \Rightarrow d=2
$$

From (i), we get

$$
\begin{aligned}
a_{1} & =\frac{13}{2}-3 d \\
& =\frac{13}{2}-6 \\
& =\frac{1}{2}
\end{aligned}
$$

Thus, $\quad a_{2}$ of the A.P. $=a_{1}+d=\frac{1}{2}+2=\frac{5}{2}$
and $\quad a_{3}$ of the A.P. $=a_{1}+2 d=\frac{1}{2}+2(2)$

$$
\begin{aligned}
& =\frac{1}{2}+4 \\
& =\frac{9}{2}
\end{aligned}
$$

Hence the required H.P. is $\frac{2}{1}, \frac{2}{5}, \frac{2}{9}, \frac{2}{13}, \ldots$

# 6.9.1 Harmonic Mean (H.M.) 

A number $H$ is said to be the harmonic mean (H.M.) between two numbers $a$ and $b$ if $a, H, b$ are in H.P.

Let $a, b$ be the two numbers and $H$ be their H.M. Then $\frac{1}{a}, \frac{1}{H}, \frac{1}{b}$ are in A.P.
Therefore, $\quad \frac{1}{H}=\frac{\frac{1}{a}+\frac{1}{b}}{2}=\frac{b+a}{a b}=\frac{a+b}{2 a b}$.
and $\quad H=\frac{2 a b}{a+b}$
For example, H.M. between 3 and 7 is

$$
\frac{2 \times 3 \times 7}{3+7}=\frac{2 \times 21}{10}=\frac{21}{5}
$$

### 6.9.2 n Harmonic Means between two Numbers

$H_{1}, H_{2}, H_{3}, \cdots, H_{n}$ are called $n$ harmonic means (H.Ms.) between $a$ and $b$ if $a, H_{1}, H_{2}, H_{3}, \cdots, H_{n}, b$ are in H.P. If we want to insert $n$ H.Ms., between $a$ and $b$, we first find $n$ A.Ms. $A_{1}, A_{2}, \ldots, A_{n}$ between $\frac{1}{a}$ and $\frac{1}{b}$, then take their reciprocals to get $n$ H.Ms. between $a$ and $b$, that is, $\frac{1}{A_{1}}, \frac{1}{A_{2}}, \cdots, \frac{1}{A_{n}}$ will be the required $n$ H.Ms. between $a$ and $b$.
Example 24 Find three harmonic means between $\frac{1}{5}$ and $\frac{1}{17}$.
Solution Let $A_{1}, A_{2}, A_{3}$ be three A.Ms. between 5 and 17, that is,

$$
5, A_{1}, A_{2}, A_{3}, 17 \text { are in A.P. }
$$

Using $\quad a_{n}=a_{1}+(n-1) d$, we get

$$
\begin{aligned}
17 & =5+(5-1) d \\
4 d & =12 \\
\Rightarrow \quad d & =3
\end{aligned} \quad\left(\because a_{2}=17 \text { and } a_{1}=5\right)
$$

Thus, $\quad A_{1}=5+3=8, A_{2}=5+2(3)=11$ and $A_{3}=5+3(3)=14$
Hence $\frac{1}{8}, \frac{1}{11}, \frac{1}{14}$ are the required harmonic means.

# EXERCISE 6.9 

1. Find the $9^{\text {th }}$ term of the following harmonic sequences:
(i) $\frac{1}{3}, \frac{1}{5}, \frac{1}{7}, \ldots$
(ii) $\frac{-1}{5}, \frac{-1}{3},-1, \ldots$
2. Insert five harmonic means between the following given numbers:
(i) $\frac{-2}{5}$ and $\frac{2}{13}$
(ii) $\frac{1}{4}$ and $\frac{1}{24}$
3. The first term of an H.P. is $-\frac{1}{3}$ and the fifth term is $\frac{1}{5}$. Find its $9^{\text {th }}$ term.
4. If 5 is the harmonic mean between 2 and $b$, find $b$.
5. If the numbers $\frac{1}{k}, \frac{1}{2 k+1}$ and $\frac{1}{4 k-1}$ are in harmonic sequence, find $k$.
6. Find $n$ so that $a^{n+1}+b^{n+1}$ may be H.M. between $a$ and $b$.
7. If $a^{2}, b^{2}$ and $c^{2}$ are in A.P., show that $a+b, c+a$ and $b+c$ are in H.P.
8. If the H.M. and A.M. between two numbers are 4 and $\frac{9}{2}$ respectively, find the numbers.
9. If the (positive) G.M. and H.M. between two numbers are 4 and $\frac{16}{5}$, find the numbers.
10. If $\frac{b+c-a}{a} \frac{c+a-b}{b}, \frac{a+b-c}{c}$ are in A.P., show that $a, b, c$ are in H.P.

11. If $a, b, c, d$ are in H.P., show that $3(a-b)(c-d)=(b-c)(a-d)$.
12. If between any two numbers there are inserted two A.Ms. $A_{1}, A_{2}$, two G.Ms. $G_{1}$, $G_{2}$ and two H.Ms. $H_{1}, H_{2}$; show that $\frac{A_{1}+A_{2}}{G_{1} G_{2}}=\frac{H_{1}+H_{2}}{H_{1} H_{2}}$.
13. The H.M. of two numbers is 4 . The A.M., $A$ and the G.M., $G$ satisfy the relation $2 A+G^{2}=27$. Find the numbers.
14. First three of the four numbers $a, b, c, d$ are in A.P., and the next three are in H.P., show that $a d=b c$.
15. If $a, b, c$ are in G.P., show that $\log _{a} x, \log _{b} x, \log _{c} x$ are in H.P.
16. If $a, b, c$ are in H.P., show that
(i) $\frac{a-b}{b-c}=\frac{a}{c}$
(ii) $(a-c)^{2}=(a+c)\left(a-2 b+c\right)$.
17. If $2+x, 5+x$ and $9+x$ are in H.P., find the value of $x$.
18. If the roots of the equation $a(b-c) x^{2}+b(c-a) x+c(a-b)=0$ are equal, prove that $a, b, c$ are in H.P.

# 6.10 Miscellaneous Series 

The Greek letter $\Sigma$ (sigma) is used to denote sums of different types. For example, the notation $\sum_{i=m}^{n} a_{i}$ is used to express the $\operatorname{sum} a_{m}+a_{m+1}+a_{m+2}+\cdots+a_{n}$ and the sum expression $1+3+5+\cdots$ to $n$ terms is written as $\sum_{k=1}^{n}(2 k-1)$, where $2 k-1$ is the $k^{\text {th }}$ term of the sum and $k$ is called the index of summation. 1 and $n$ are called the lower limit and upper limit of summation respectively.
The sum of the first $n$ natural numbers, the sum of squares of the first $n$ natural numbers and the sum of the cubes of the first $n$ natural numbers are expressed in sigma notation as:

$$
1+2+3+\cdots+n=\sum_{k=1}^{n} k ; 1^{2}+2^{2}+3^{2}+\cdots+n^{2}=\sum_{k=1}^{n} k^{2} ; 1^{3}+2^{3}+3^{3}+\cdots+n^{3}=\sum_{k=1}^{n} k^{3}
$$

We evaluate $\sum_{k=1}^{n}\left[k^{m}-(k-1)^{m}\right]$ for any positive integer $m$ and we shall use this result to find out formulae for three expressions stated above.

$$
\begin{aligned}
\sum_{k=1}^{n}\left[k^{m}-(k-1)^{m}\right]=\left(1^{m}-0^{m}\right)+\left(2^{m}-1^{m}\right)+\left(3^{m}-2^{m}\right)+ & \cdots \\
& +\left[(n-1)^{m}-(n-2)^{m}\right]+\left[n^{m}-(n-1)^{m}\right]=n^{m}
\end{aligned}
$$

i.e., $\quad \sum_{k=1}^{n}\left[\left(k^{m}-(k-1)^{m}\right]=n^{m}\right.$
If $m=1$, then $\sum_{k=1}^{n}\left[\left(k^{1}-(k-1)^{1}\right]=n^{1}\right.$ i.e., $\sum_{k=1}^{n} 1=n$
If $m=2$, then $\sum_{k=1}^{n}\left[k^{2}-(k-1)^{2}\right]=n^{2}$

## Properties of Summation:

(i) $\sum_{s=1}^{n}\left(a_{s}+b_{s}\right)=\sum_{s=1}^{n} a_{s}+\sum_{s=1}^{n} b_{s}$
(ii) $\sum_{s=1}^{n} \alpha a_{s}=\alpha \sum_{s=1}^{n} a_{s}$

To Find the Formulae for the Sums
(i) $\sum_{k=1}^{n} k$
(ii) $\sum_{k=1}^{n} k^{2}$
(iii) $\sum_{k=1}^{n} k^{3}$
(i) We know that $(k-1)^{2}=k^{2}-2 k+1$ and this identity can be written as:

$$
k^{2}-(k-1)^{2}=2 k-1
$$

Taking summation on both sides of (A) from $k=1$ to $n$, we have

$$
\begin{aligned}
& \sum_{k=1}^{n}\left[\left(k^{2}-(k-1)^{2}\right]=\sum_{k=1}^{n}(2 k-1)\right. \\
& \text { i.e., } \\
& n^{2}=2 \sum_{k=1}^{n} k-n \\
& \text { or } \\
& 2 \sum_{k=1}^{n} k=n^{2}+n \\
& \text { Thus }
\end{aligned}
$$

$$
\sum_{k=1}^{n} k=\frac{n(n+1)}{2}
$$

Similarly, we can prove easily
(ii) $\sum_{k=1}^{n} k^{2}=\frac{n(n+1)(2 n+1)}{6}$
(iii) $\sum_{k=1}^{n} k^{3}=\left[\frac{n(n+1)}{2}\right]^{2}$

Example 25 Find the sum of the series $1^{3}+3^{3}+5^{3}+\ldots$ to $n$ terms.
Solution $T_{k}=(2 k-1)^{2} \quad(\because 1+2(k-1)=2 k-1)$

$$
=8 k^{3}-12 k^{2}+6 k-1
$$

Let $S_{n}$ denote the sum of $n$ terms of the given series, then

$$
S_{n}=\sum_{k=1}^{n} T_{k}
$$

or

$$
S_{n}=\sum_{k=1}^{n}\left(8 k^{3}-12 k^{2}+6 k-1\right)
$$

$$
\begin{aligned}
& =8 \sum_{k=1}^{n} k^{3}-12 \sum_{k=1}^{n} k^{2}+6 \sum_{k=1}^{n} k-\sum_{k=1}^{n} 1 \\
& =8\left[\frac{n(n+1)}{2}\right]^{2}-12\left[\frac{n(n+1)(2 n+1)}{6}\right]+6\left[\frac{n(n+1)}{2}\right]-n \\
& =2 n^{2}(n+1)^{2}-2 n(n+1)(2 n+1)+3 n(n+1)-n \\
& =2 n^{2}\left(n^{2}+2 n+1\right)-2 n\left(2 n^{2}+3 n+1\right)+n(3 n+3)-n \\
& =2 n\left[\left(n^{3}+2 n^{2}+n\right)-\left(2 n^{2}+3 n+1\right)\right]+n(3 n+3-1) \\
& =2 n\left(n^{3}-2 n-1\right)+n(3 n+2) \\
& =2 n\left(n^{3}-2 n-1\right)+n(3 n+2) \\
& =n\left[2 n^{3}-4 n-2+3 n+2\right] \\
& =n\left[2 n^{3}-n\right]=n\left[n\left(2 n^{2}-1\right)\right] \\
& =n^{2}\left[2 n^{2}-1\right]
\end{aligned}
$$

Example 26 Find the sum of $n$ terms of series whose $n^{\text {th }}$ terms is $n^{3}+\frac{3}{2} n^{2}+\frac{1}{2} n+1$.
Solution Given that

$$
T_{n}=n^{3}+\frac{3}{2} n^{2}+\frac{1}{2} n+1
$$

Thus

$$
T_{k}=k^{3}+\frac{3}{2} k^{2}+\frac{1}{2} k+1
$$

and

$$
5_{n}=\sum_{k=1}^{n}\left(k^{3}+\frac{3}{2} k^{2}+\frac{1}{2} k+1\right)
$$

$$
\begin{aligned}
& =\sum_{k=1}^{n} k^{3}+\frac{3}{2} \sum_{k=1}^{n} k^{2}+\frac{1}{2} \sum_{k=1}^{n} k+\sum_{k=1}^{n} 1 \\
& =\frac{n^{2}(n+1)^{2}}{4}+\frac{3}{2} \times \frac{n(n+1)(2 n+1)}{6}+\frac{1}{2} \times\left[\frac{n(n+1)}{2}\right]+n \\
& =\frac{n}{4}\left[n\left(n^{2}+2 n+1\right)+\left(2 n^{2}+3 n+1\right)+(n+1)+4\right] \\
& =\frac{n}{4}\left(n^{3}+2 n^{2}+n+2 n^{2}+3 n+1+n+1+4\right) \\
& =\frac{n}{4}\left(n^{3}+4 n^{2}+5 n+6\right)
\end{aligned}
$$

# EXERCISE 6.10 

1. Sum the following series upto $n$ terms.
(i) $1 \times 3+2 \times 5+3 \times 7+\cdots$
(ii) $1 \times 5+2 \times 8+3 \times 11+\cdots$
(iii) $1 \times 2+2 \times 5+3 \times 8+\cdots$
(iv) $1 \times 3 \times 5+2 \times 4 \times 6+3 \times 5 \times 7+\cdots$
(v) $1 \times 2 \times 4+2 \times 3 \times 7+3 \times 4 \times 10+\cdots$
(vi) $2^{2}+4^{2}+6^{2}+\cdots$
(vii) $3^{2}+6^{2}+9^{2}+\cdots$
(viii) $4 \times 1^{2}+7 \times 2^{2}+10 \times 3^{2}+\cdots$
(ix) $3+(3+7)+(3+7+11)+\cdots$
(x) $1^{2}+\left(1^{2}+2^{2}\right)+\left(1^{2}+2^{2}+3^{2}\right)+\cdots$
2. Sum the series.
(i) $1^{2}-2^{2}+3^{2}-4^{2}+\ldots+(2 n-1)^{2}-(2 n)^{2}$
(ii) $\frac{1^{2}}{1}+\frac{1^{2}+2^{2}}{2}+\frac{1^{2}+2^{2}+3^{2}}{3}+\ldots$ to $n$ terms :
3. Find the sum to $n$ terms of the series whose $n^{\text {th }}$ terms are given.
(i) $5 n^{2}+2 n+3$
(ii) $n^{2}+2 n-3$
4. Given $n^{\text {th }}$ terms of the series, find the sum to $2 n$ terms:
(i) $3 n^{2}+5 n+2$
(ii) $n^{2}+n-2$

### 6.11 Real Life Problems involving Sequences and Series

## Example 27 Vehicle Arrival Sequence

Vehicles arrive at a toll booth at a rate of 4 cars every 5 minutes. Represent the number of cars arriving over time as a sequence and predict the total number of cars after an hour.
Solution The sequence of car arrivals is:

$$
4,8,12,16, \ldots
$$

This is an $A: P$, with
$a_{1}=4, d=4, n=\frac{60}{5}=12, a_{12}=?$
Using the formula for arithmetic sequence

$$
\begin{aligned}
a_{n} & =a_{1}+(n-1) d \\
a_{12} & =4+(12-1)(4) \\
& =4+11(4) \\
& =4+44=48
\end{aligned}
$$

Thus, after one hour there will be 48 cars.

Simple Interest on Loan (Arithmetic Sequence with Particular Term)
Example 28 To buy furniture for a new apartment Tayyab borrowed Rs. 50,000 at $8 \%$ simple interest for 11 years. How much interest will he pay?
Solution Since $8 \%$ is the yearly interest rate, we have

$$
\begin{aligned}
& \text { Interest after one year }=\text { Rs. } 50,000 \times \frac{8}{100} \times 1=\text { Rs. } 4000 \\
& \text { Interest after two years }=\text { Rs. } 50,000 \times \frac{8}{100} \times 2=\text { Rs. } 8000
\end{aligned}
$$

Therefore, we have the A.P.

$$
4000,8000,12000, \ldots
$$

Here, $a_{1}=4000, a_{2}=8000, d=a_{2}-a_{1}=4000, n=11$
Using the formula

$$
\begin{aligned}
a_{n} & =a_{1}+(n-1) d \\
a_{11} & =4000+(11-1)(4000) \\
& =4000+10(4000) \\
& =4000+40000 \\
& =\text { Rs. } 44000
\end{aligned}
$$

Thus, Tayyab will pay a total interest of Rs. 44000 on borrowed amount of Rs 50,000 after 11 years.
Compound Interest on Loan (Geometric Sequence with Particular Term)
Example 29 Amna invests Rs. 200000 at $5 \%$ interest compounded annually. What total amount will she get after 10 years?
Solution Let the principal amount be $P$. Then,
The interest for the first year $=P \times \frac{5}{100}=P(0.05)$
The total amount after first year $=P+P(0.05)=P(1+0.05)$
The interest for the second year $=P(1+0.05) \times 0.05$
The total amount after second year $=P(1+0.05)+P(1+0.05) \times 0.05$

$$
\begin{aligned}
& =P(1+0.05)(1+0.05) \\
& =P(1+0.05)^{2}
\end{aligned}
$$

Similarly, the total amount after third year $=P(1+0.05)^{3}$
Thus, we have sequence of amounts

$$
P(1.05), P(1.05)^{2}, P(1.05)^{3}, \ldots
$$

which is clearly a G.P., with

$$
a_{1}=P(1.05), r=1.05, n=10, a_{10}=?
$$

Using the geometric sequence formula

$$
\begin{aligned}
a_{n} & =a_{1} r^{n-1} \\
a_{10} & =a_{1} r^{10-1} \\
& =P(1.05) \times(1.05)^{9} \\
& =(200000)(1.05)^{10} \quad P=200000 \\
& =(200000)(1.62889) \\
& =325778.92
\end{aligned}
$$

Thus, the total amount Amna will get after 10 years will be Rs. 325778.92
Grid Column Distribution (Arithmetic Series Sum of Terms)
Example 30 A web designer is using a 12 -column grid system where each column increases in width by $10 p x$ from the previous one. The first column width is $50 p x$ wide. Find the total width occupied by all 12 columns.
Solution This follows an arithmetic series with:
First term $=a_{1}=50$, Common difference $=d=10$
Number of terms $=n=12$
Using the formula for the sum of an arithmetic series:

$$
\begin{aligned}
S_{n} & =\frac{n}{2}\left[2 a_{1}+(n-1) d\right] \\
S_{12} & =\frac{12}{2}[2(50)+(12-1)(10)] \\
& =6[100+110]=6[210] \\
& =1260 p x
\end{aligned}
$$

Thus, the total width of all 12 columns is $1260 p x$.
Example 31 Motor Vehicle Leasing Using Arithmetic Sequence
A company leases a motor vehicle with the following terms:

- The first monthly payment is Rs. 15,000
- Each subsequent payment increases by Rs. 500 due to inflation adjustments.
- The lease term is 24 months.

Find:
(i) What is the payment in the $24^{\text {th }}$ month?
(ii) What is the total amount paid over 24 months?
(iii) If the company can only afford to pay a total of Rs. 400,000 , can they complete the 24 -months lease?
(iv) Find maximum months $n$ such that total, payment $S_{n} \leq 400,000$.

# Solution Given: 

$$
\begin{aligned}
\text { First term }=a_{1} & =15000 \\
\text { Common difference } & =d=500 \\
\text { Number of terms } & =n=24
\end{aligned}
$$

(i) Payment in $24^{\text {th }}$ month:

Using the formula

$$
\begin{aligned}
a_{n} & =a_{1}+(n-1) d \\
a_{24} & =15000+(24-1)(500) \\
& =15000+23 \times 500 \\
& =15000+11500=\text { Rs. } 26500
\end{aligned}
$$

(ii) Total payment over 24 months using the formula

$$
\begin{aligned}
S_{n} & =\frac{n}{2}\left(a_{1}+a_{n}\right) \\
& =\frac{24}{2}(15000+26500)=12(41500)=\text { Rs. } 498000
\end{aligned}
$$

(iii) Can the company afford the lease? No, total payments (Rs. 498000) exceed the budget of Rs. 400,000 by Rs. 98,000 .
(iv) Using: $S_{n}=\frac{n}{2}\left[2 a_{1}+(n-1) d\right] \leq 400,000$

Substituting the values:

$$
\begin{gathered}
\frac{n}{2}[2(15000)+(n-1)(500)] \leq 400,000 \\
n[15000+250 n-250] \leq 400,000 \\
n(250 n+14750) \leq 400,000 \\
250 n^{2}+14750 n-400000 \leq 0 \\
n^{2}+59 n-1600 \leq 0
\end{gathered}
$$

Associated equation is $n^{2}+59 n-1600=0$

$$
\begin{aligned}
& n=\frac{-59 \pm \sqrt{(59)^{2}-4(1)(-1600)}}{2(1)} \\
& n=\frac{-59 \pm 99.4}{2} \\
& n=\frac{-59-99.4}{2}, n=\frac{-59+99.4}{2} \\
& n=-79.2, n=20.2
\end{aligned}
$$

Clearly $n=20$ satisfy the inequality.
So, $n=20$ is the maximum months such that payment $S_{n} \leq 400,000$.

# EXERCISE 6.11 

1. A sum of Rs. 10400 is paid off in 40 instalment such that each instalment is Rs. 10 more than the preceding instalment. Calculate the value of the first instalment.
2. An investor invests Rs. 150000 at an annual compound interest rate of $6 \%$ for 8 years. Find the total amount will he get after 8 years.
3. The population of a town is 4084101 at present and five years ago it was 3200000 . Find its rate of increase if it increased geometrically.
4. Determine the total worth of a yearly Rs. 5000 investment after 20 years if the interest rate is $5 \%$ compounded annually.
5. A water tank has a leakage. Each week, the tank loses 5 gallons of water due to the leakage. Initially, the tank is full and contains 2000 gallons.
(i) How many gallons are in the tank 20 weeks later?
(ii) How many weeks until the tank is half-full?
(iii) How many weeks until the tank is empty?
6. A drug company has manufactured 7 million doses of a vaccine to date. They promise additional production at a rate of 1.4 million doses/month over the next year.
(i) How many doses of the vaccine, in total, will have been produced after a year?
(ii) The general term $a_{n}$ describes the total number of doses of the vaccine produced. Describe the meaning of the variable $n$ in the context of this problem. Find the general term $a_{n}$
(iii) Find the value of $a_{10}$ and interpret its meaning in words.
7. At a toll-bent, the number of vehicles passing through during the first minute is 100 . Due to road congestion, each minute only $80 \%$ of the vehicles from the previous minute manage to pass.
(i) Represent the number of vehicles passing each minute as a sequence.
(ii) Find the total number of vehicles that pass through in 15 minutes.
(iii) What is the maximum number of vehicles that can pass in the long run (as time $t \rightarrow \infty$ )
8. A sum of Rs. 5000 is inverted at $8 \%$ simple interest per year. Calculate the interest at the end of each year. Do these interests form an A.P.? If so find the interest at the end of 20 years making use of this fact.

9. A machine is purchased for Rs.20,000. Depreciates at 6% per annum for the first four years and after that 8% per annum for the next six years. Depreciation being calculated on diminishing value. Find the value of the machine after a period of 10 years.
10. Two cars start together in the same direction from the same place. The first goes with uniform speed of 20km/h. The second goes at a speed of 12km/h in the first hour and increases the speed by 1 km/h each succeeding hour. After how many hours will the second car overtake the first car if both cars go non-stop?
11. 150 workers were engaged to finish a piece of work in a certain number of days. Five workers dropped the second day, five more workers dropped the third day and so on. It takes 10 more days to finish the work now. Find the number of days in which the work was completed.
12. A radioactive product has a half life of 5 years. If the radioactivity level is 68 microcuries after 20 years. Determine the original level of radioactivity.
13. An object moving in a line is given an initial velocity of 4.5 m/s and a constant acceleration of 2.5 m/s². How long will it take the object to reach a velocity of 20m/s?
14. In an integrated circuit with an initial current of 1080 mA, the temperature in the components decreases from 20% to 17% to 14%. Assuming that each temperature decrease is caused by a decrease in the initial current, what is the value of the current at fourth measurement?
15. Show that the amount of a certain sum of money at compound interest of r% per year for n years form a G.P.

# Permutations and Combinations 

## INTRODUCTION

In our daily life, permutations and combinations play a vital role in counting total number of possibilities, as well as in arrangements and selections of objects. They are used in many fields of science. For example,

- In probability theory, permutations and combinations are used to compute how many times an event can occur in various scenarios and to estimate the odds of winning a lottery.
- In biology, these are used to find out the total numbers of possible DNA sequences.
[Image removed]
- In computer science, these are used to count the possible number of passwords of a given length by using some specific characters.
- Moreover, these are the important parts of many encryption algorithms to ensure the privacy and integrity of a data set.


### 7.1 Fundamental Principle of Counting

Danish wants to prepare invitation cards of 5 different colours (red, blue, green, orange and yellow) by changing any of 3 shapes (circle, square and rectangle). How many cards can Danish make?
The problem is to count the total number of ways in which Danish can make cards. One way to find the solution is by making tree diagram. Let us discuss another scenario: Danish's father wants to buy a table and has asked his son to help him decide. He narrowed down his options for manufacturer, types of material (wood, plastic, glass and marble) and types of shape (circle, square and rectangle). Find the total number of table choices from the above options.
Again the problem is to count the total number of ways in which Danish's father can choose a table.

$1^{\text {st }}$ Way: By making tree diagram.
[Image removed]

From tree diagram, it is clearer there are 12 choices for Danish's father to buy a table with one type of material and one type of shape.
$2^{\text {nd }}$ Way: By multiplying, Danisah's father can find the total number of table choices to buy a table with one kind of material and shape.
Total number of table choices $=$ Total types of material $\times$ Total types of shape

$$
=4 \times 3=12 \text { choices }
$$

These examples show that when making a choice involving multiple stages or categories, we can find the total number of outcomes by multiplying the number of options at each stage.

# Statement 

Suppose $A$ and $B$ are two events, the event $A$ occurs in $m$ different ways, and the event $B$ occurs in $n$ different ways then the total number of ways that the two events one after another can occur in $m \times n$ ways.

$$
\text { Total number of ways }=m n
$$

Proof: Let $A=\left\{a_{1}, a_{2}, a_{3}, \cdots, a_{m}\right\}$ and $B=\left\{b_{1}, b_{2}, b_{3}, \cdots, b_{n}\right\}$. Let $P$ denotes the event that both events $A$ and $B$ occur together then $P=\left\{\left(a_{i}, b_{j}\right): a_{i} \in A, b_{j} \in B, 1 \leq i \leq m\right.$, $1 \leq j \leq n\}=A \times B$. Hence the number of ways in which both events $A$ and $B$ can occur is the number of elements in $A \times B$ which is $m n$.
This principle can be extended to three or more events. For instance, if event $A$ can occur in $m$ ways, event $B$ can occur in $n$ ways and event $C$ can occur in $k$ ways, the number of ways that three events can occur all together is the

## Try yourself!

If three dice are rolled together, how many total numbers of ways occur?

product $m \cdot n \cdot k$.

## Factorial (I)

Suppose there are four chairs to be occupied by four students and we are interested in counting all the possible ways the students can be seated.
To occupy the first chair there are 4 options. For the second chair, only 3 students remain, so there are 3 options. Similarly, for the third and fourth chairs, there are 2 and 1 options respectively.

In this way, we have to perform four independent events with $4,3,2$, and 1 options respectively.
By the Fundamental Principle of Counting, the total number of ways to occupy all the chairs is $4 \cdot 3 \cdot 2 \cdot 1=24$
Such problems frequently occur in daily life, where we have to multiply the first $n$ natural numbers: $1,2,3, \cdots, n$.
We call this product the factorial of $n$ and denote it by $n!$ or $\mid n$, thus for a natural number $n$ :

$$
n!\text { or } \quad \underline{n}=n(n-1)(n-2) \cdots 3 \cdot 2 \cdot 1
$$

For some reason we also define $0!=1$. In general, if $n$ is a non-negative integer, then its factorial is denoted and defined as

$$
n!=\mid \underline{n}= \begin{cases}1 & \text { if } n=0 \\ n(n-1)(n-2) \ldots 3 \cdot 2 \cdot 1 & \text { if } n \geq 1\end{cases}
$$

For example,

$$
\begin{aligned}
& 1!=1 \\
& 2!=2 \cdot 1=2 \\
& 3!=3 \cdot 2 \cdot 1=6 \\
& 4!=4 \cdot 3 \cdot 2 \cdot 1=24 \\
& 5!=5 \cdot 4 \cdot 3 \cdot 2 \cdot 1=120 \\
& 6!=6 \cdot 5 \cdot 4 \cdot 3 \cdot 2 \cdot 1=720
\end{aligned}
$$

Challenged
Can you find out $\frac{81}{3!}$ ?

It can be easily observed that

$$
n!=n(n-1)!\text { for } n \geq 1
$$

Example 1 Evaluate $\frac{8!}{6!}$
Solution $\frac{8!}{6!}=\frac{8 \cdot 7 \cdot 6 \cdot 5 \cdot 4 \cdot 3 \cdot 2 \cdot 1}{6 \cdot 5 \cdot 4 \cdot 3 \cdot 2 \cdot 1}=56$
Example 2 Write $8 \cdot 7 \cdot 6 \cdot 5$ in the factorial form.

Solution $8 \cdot 7 \cdot 6 \cdot 5=\frac{8 \cdot 7 \cdot 6 \cdot 5 \cdot 4 \cdot 3 \cdot 2 \cdot 1}{4 \cdot 3 \cdot 2 \cdot 1}=\frac{8!}{4!}$ or $\frac{9!}{6!3!}=\frac{9 \cdot 8 \cdot 7 \cdot 6 \cdot 5 \cdot 4 \cdot 3 \cdot 2 \cdot 1}{6 \cdot 5 \cdot 4 \cdot 3 \cdot 2 \cdot 1 \cdot 3 \cdot 2 \cdot 1}=84$

# EXERCISE 7.1 

1. Evaluate each of the following:
(i) $\frac{10!}{0!8!}$
(ii) $\frac{12!}{3!(12-3)!}$
(iii) $\frac{1440}{3!4!}+\frac{2400}{5!2!}$
(iv) $\frac{(n+2)!}{(n+1)!}$
2. Write each of the following in the factorial form:
(i) $n^{2}-n$
(ii) $n(n-1)(n-2) \cdots(n-r+1)$
3. Find $n$, if $(n+4)!=3024 \cdot n!$.
4. If $\frac{1}{7!}+\frac{1}{8!}=\frac{x}{9!}$, find $x$.
5. Prove that: $\frac{(2 n+1)!}{n!}=[1 \cdot 3 \cdot 5 \cdots(2 n-1)(2 n+1)] 2^{n}$
6. Express as a single fraction: $\frac{(n+2)!}{(r+2)!}+\frac{(n+1)!}{(r+1)!}$.
7. There are four distinct colored balls and four boxes of same colors as those of the balls. Determine the number of possible ways the balls, one each in a box, can be placed such that a ball does not go to a box of its own colour?

### 7.2 Permutations

One important application of the fundamental principle of counting is to determine the number of ways that objects can be arranged in order.
Definition: An arrangement of all or part of set of objects in a specific order is called a permutation. Number of permutations of $r(\leq n)$ objects taken from a set of $n$ objects is written as ${ }^{\circ} P_{r}$ or $P\left(n_{r} r_{r}\right)$.

$$
{ }^{\circ} P_{r}=\frac{n!}{(n-r)!} \quad \text { when } r \leq n
$$

According to fundamental principle of counting:
(i) Three books of mathematics for grades 1,2 and 3 can be arranged in a row taken all at a time (if books are distinct)

$$
\begin{aligned}
{ }^{\circ} P_{r} & ={ }^{3} P_{3} & \because n=r \approx 3 \\
& =\frac{3!}{(3-3)!}=\frac{3!}{0!} & \because 0!=1 \\
& =3!=3 \cdot 2 \cdot 1=6 \text { ways }
\end{aligned}
$$

(ii) Number of ways of writing the letters of the WORD taken all at a time
[Image removed]

$$
\begin{aligned}
& { }^{n} P_{r}={ }^{4} P_{4} \\
& n=r=4 \\
& n=\text { Total number of things/objects } \\
& =\frac{4!}{(4-4)!}=\frac{4!}{0!} \\
& r=\text { The number of selected things / objects } \\
& =4!=4 \cdot 3 \cdot 2 \cdot 1=24 \text { ways }
\end{aligned}
$$

| Challenge! | Do you know! |
| :-- | :-- |
| Can you make total number of <br> permutations for the "WORD" <br> pictorially? | In 1974, "fimo Rubik" invented a popular <br> puzzle, each turn of the puzzle shows a <br> permutation of the different colours. The <br> name of this puzzle is "Rubik's Cube". |

Theorem: Prove that: ${ }^{n} P_{r}=n(n-1)(n-2) \cdots(n-r+1)=\frac{n!}{(n-r)!}$
Proof: As there are $n$ different objects to fill up $r$ places. So, the first place can be filled in $n$ ways. Since repetitions are not allowed, so after placing one object we are left with $(n-1)$ objects, thus the second place can be filled in $(n-1)$ ways. Similarly the third place can be filled in $(n-2)$ ways, and so on. This continues until the $r^{\text {th }}$ place which can be filled in $n-(r-1)=n-r+1$ ways. Therefore, by the Fundamental Principle of Counting, $r$ places can be filled by $n$ different objects in $n(n-1)(n-2) \cdots(n-r+1)$ ways.

$$
\begin{aligned}
{ }^{n} P_{r} & =n(n-1)(n-2) \ldots(n-r+1) \\
& =\frac{n(n-1)(n-2) \ldots(n-r+1)(n-r)!}{(n-r)!} \\
{ }^{n} P_{r} & =\frac{n!}{(n-r)!}
\end{aligned}
$$

Example 4 How many different 4-digit numbers can be formed out from the digits $1,2,3,4,5,6$, when no digit is repeated?
Solution The total number of digits $=6$
The digits forming each number $=4$
So, the required number of 4-digit numbers is given by:

$$
{ }^{6} P_{4}=\frac{6!}{(6-4)!}=\frac{6!}{2!}=\frac{6 \cdot 5 \cdot 4 \cdot 3 \cdot 2 \cdot 1}{2.1}=6 \cdot 5 \cdot 4 \cdot 3=360
$$

Example 5 In how many ways can a set of 4 different mathematics books, 3 different physics books and 2 different chemistry books be placed on a shelf with a space for 9 books, if:
(a) all the books are kept without any restriction.

(b) all the books of the same subject are kept together.
(c) only the mathematics books are kept together.

# Soiation 

(a) all the books are kept without any restriction.
Total number of books $=4+3+2=9$

$$
\begin{aligned}
& { }^{9} P_{2}=9!=9 \cdot 8 \cdot 7 \cdot 6 \cdot 5 \cdot 4 \cdot 3 \cdot 2 \cdot 1 \quad 91 \text { ways } \\
& =362880 \text { ways }
\end{aligned}
$$

[Image removed]
(b) all the books of the same subject are kept together.

$$
\begin{aligned}
& { }^{4} P_{4} \cdot{ }^{3} P_{3} \cdot{ }^{2} P_{2} \cdot{ }^{3} P_{1}=4!\cdot 3!\cdot 2!\cdot 3! \\
& =24 \cdot 6 \cdot 2 \cdot 6 \\
& =1728 \text { ways }
\end{aligned}
$$

(c) only the mathematics books are kept together.

$$
\begin{aligned}
& { }^{4} P_{4} \cdot{ }^{6} P_{3}=4!\cdot 6! \\
& =24 \cdot 720 \\
& =17280 \text { ways }
\end{aligned}
$$

[Image removed]

Example 6 In how many ways 5 people are to be seated on a bench if:
(a) there are no restrictions
(b) two people can sit next to each other
(c) two people cannot sit next to each other.

## Solution

(a) when there is no restriction, then

$$
\text { Number of ways }={ }^{5} P_{2}=5!=120
$$

(b) when two people can sit next to each other, then

$$
\begin{aligned}
& ={ }^{4} P_{4} \cdot{ }^{2} P_{2} \\
& =4!\cdot 2!=24 \cdot 2 \\
& =48 \text { ways }
\end{aligned}
$$

[Image removed]

## C D E

51 ways
[Image removed]

## Try yourself!

In how many ways 6 people are to seated on a table if 3 cannot sit next to each other?

# EXERCISE 7.2 

1. Evaluate the following:
(i) ${ }^{10} P_{2}$
(ii) ${ }^{3} P_{2}$
(iii) ${ }^{7} P_{7}$
(iv) ${ }^{10} P_{2}$
2. Find the value of $n$ when:
(i) ${ }^{n} P_{3}=504$
(ii) ${ }^{15} P_{n}=15 \cdot 14 \cdot 13 \cdot 12 \cdot 11$
(iii) ${ }^{n} P_{3}:^{n-2} P_{2}=540: 1$
3. Prove from the first principle that:
(i) ${ }^{n} P_{r}=n \cdot{ }^{n-1} P_{r-1}$
(ii) ${ }^{n} P_{r}={ }^{n-1} P_{r}+r \cdot{ }^{n-1} P_{r-1}$
4. How many words can be formed from the letters of the following words using all letters when no letter is to be repeated:
(i) PYTHON
(ii) NETWORK
(iii) COMPUTER
5. How many signals can be given by 6 flags of different colours, using 2 flags at a time?
6. How many signals can be given by 5 flags of different colours, when any number of flags are used at a time.
7. How many 4 digit numbers can be formed, with distinct digits, with each digit odd?
8. How many numbers between 100 and 1000 can be formed by using the digits $0,1,2,3,4,5$ without repetition? How many of them are divisible by 5 ?
9. Find the numbers greater than 35000 that can be formed from the digits $1,2,3,4,5,6$, without repeating any digit.
10. Find the number of 5 -digit numbers that can be formed from the digits $1,2,4,6$, 8 (when no digit is repeated), but
(i) the digits 2 and 8 are next to each others;
(ii) the digits 2 and 8 are not next to each other.
11. How many 6-digit numbers can be formed, without repeating any digit from the digits $0,1,2,3,4,5$ ? In how many of them will 0 be at the tens place?
12. How many 5-digit multiples of 5 can be formed from the digits $2,3,5,7,9$, when no digit is repeated.
13. In how many ways can 8 different books including 2 on English be arranged on a shelf in such a way that the English books are never together?
14. Find the number of arrangements of 3 different books on English and 5 different books on Urdu for placing them on a shelf such that the books on the same subject are together.
15. In how many ways can 5 boys and 4 girls be seated on a bench so that the girls and the boys occupy alternate seats?

# 7.3 Permutation of Objects Not All Different 

Suppose we have to find the permutations of the letters of the word BITTER using all the letters. The word BIT ${ }_{1} \mathrm{~T}_{2}$ ER consists of 6 different letters which can be permuted among themselves in 6 ! ways.
We can see that all the letters of the word BITTER are not different. It has 2Ts in it. We can see there are 2 ! ways of replacing two $\mathrm{T}_{8}$ :

BITT $T_{1}$ ER
BITT $T_{1}$ ER
The replacement of the two $\mathrm{T}_{8}$ by $\mathrm{T}_{1}$ and $\mathrm{T}_{2}$ in any other permutation will give rise to 2 permutations.
Hence, the number of permutations of the letters of the word BITTER taken all at a time.

$$
\frac{6!}{2!}=\frac{6 \cdot 5 \cdot 4 \cdot 3 \cdot 2 \cdot 1}{2.1}=360 \text { ways }
$$

## Remember!

If there are $n_{1}$ alike objects of one kind, $n_{2}$ alike objects of second kind and $n_{n}$ alike objects are of third kind, then the number of permutations of $n$ objects taken all at a time is given by:

$$
\frac{n!}{n_{1}!\cdot n_{2}!\cdot n_{3}!}=\binom{n}{n_{1}, n_{2}, n_{3}}
$$

Example 7 In how many ways can the letters of the word MISSISSIPPI be arranged when all the letters are to be used?
Solution Total number of letters in the word $=11$

## MISSISSIPPI

I is repeated 4 times $=4$ I ways
$S$ is repeated 4 times $=4$ I ways
$P$ is repeated 2 times $=2$ I ways
$M$ comes once only $=11$ ways
Required number of permutations $=\frac{11!}{4!\cdot 4!\cdot 2!\cdot 1!}=34650$ ways

## Circular Permutations

The permutations in which the object are arranged in a circular order are known as circular permutations.

## Note:

The following circular arrangements are reflection of each other and considered same when anticlockwise and clockwise arrangements are considered identical.
[Image removed]

Circular permutations can occur in two cases:
Case-I: When clockwise and anticlockwise arrangements are considered different In a linear arrangement, changing the order of objects results in a new arrangement. However, in a circular arrangement, rotating the entire circle does not produce a new, distinct arrangement.

For example, suppose three people $\mathrm{A}, \mathrm{B}$ and C are sitting around a round table. The following three linear arrangements
$\mathrm{A}-\mathrm{B}-\mathrm{C}, \mathrm{B}-\mathrm{C}-\mathrm{A}$ and $\mathrm{C}-\mathrm{A}-\mathrm{B}$ are considered the same in circular permutations because each one is simply a rotation of the other.
We conclude that:
3 linear permutations gives 1 circular permutation.
3 ! linear permutations gives $\frac{1}{3} \cdot 3!=\frac{3!}{3}=2$ ! permutations.
Generalizing the above idea if $n$ objects are arranged in a circle, the number of distinct circular permutations is $\frac{n!}{n}=(n-1)!$.

Case-II: When clockwise and anticlockwise arrangements are considered identical
In many real-life situations, a circular permutation and its mirror image are not considered different.
For example, if three beads red, blue, and black are arranged in a ring, then an arrangement and its reflection (as shown in the figure) are considered the same.
In such cases, we divide the total number of circular permutations by 2 to eliminate symmetrical duplicates.
Thus, in this case the number of distinct circular permutations is:

$$
\frac{(n-1)!}{2}
$$

Example 8 In how many ways can 4 persons be seated at a round table, while:
(i) clockwise and anticlockwise orders are different
(ii) clockwise and anticlockwise orders are identical.

Solution Let $A, B, C$ and $D$ be the 4 persons.
(i) If clockwise and anticlockwise orders are different

# According to Case-I 

The possible number of ways are:

$$
\begin{aligned}
& =(n-1)!\text { ways } \\
& =(4-1)!=3! \\
& =3 \cdot 2 \cdot 1=6 \text { ways. }
\end{aligned}
$$

(ii) If clockwise and anticlockwise orders are identical

According to Case-II
The possible number of ways are $=\frac{(n-1)!}{2}$ ways

$$
\begin{aligned}
& =\frac{(4-1)!}{2}=\frac{31}{2} \\
& =\frac{3 \cdot 2}{2}=3 \text { ways }
\end{aligned}
$$

# EXERCISE 7.3 

1. How many arrangements of the letters of the following words, taken all together can be made?
(i) PAKISTAN
(ii) CURRICULUM
(iii) PROBABILITY
2. How many permutations of the letters of the word "BANANA" can be made, if B must be the first letter in each arrangement?
3. How many arrangements of the letters of the word TRIGONOMETRY can be made, if each arrangement begins with T and ends with Y ?
4. Abdullah has a collection of 9 marbles consisting of 4 identical red marbles, 3 identical blue marbles and 2 identical green marbles. If he wants to arrange all of them is a straight row, how many distinct arrangements are possible?
5. In how many different ways can the following persons sit around a round table?
(a) 8 persons
(b) 7 persons
(c) 6 persons
6. In how many ways can 5 couples sit around a round table if no two women are sitting together?
7. How many 6 -digit numbers can be formed from the digits $7,7,8,8,9,9$ ?
8. 15 members of a club form 4 committees of $3,5,4$ and 3 members so that no member is a member of more than one committee. Find the number of committees.
9. The D.C.Os of 11 districts meet to discuss the law-and-order situation in their districts. In how many ways can they be seated at a round table, when two particular D.C.Os insist on sitting together?
10. The Governor of the Punjab calls a meeting of 14 officers. In how many ways can they be seated at a round table?
11. Fatima invites 14 people for a dinner. There are 9 males and 5 females who are seated at two different tables. Guests of one sex sit at one round table and the guests of the other sex sit at the second table. Find the number of ways in which all guests can be seated.

12. Find the number of ways in which 5 men and 5 women can be seated at a round table in such a way that no two persons of the same sex sit together.
13. In how many ways can 8 keys be arranged in a circular key ring?
14. How many necklaces can be made from 10 beads of different colours?

# 7.4 Combinations 

Suppose, a teacher uses the names of few students to make a team for a writing competition. Such as Ahmad, Sana, Hamza and Danish. As a combination of team members, (Ahmad, Sana, Hamza and Danish) is equivalent to (Hamza, Ahmad, Danish and Sana). Because same students are in the combination. Consequently, you have the same team because the order of the name of the students does not matter.
So, we are interested in the membership of the

| Ahmad | Sana | Hamza | Danish |
| :-- | :-- | :-- | :-- |
| Hamza | Ahmad | Danish | Sana |

team and not in the ways the students are listed (arranged).

## Definition

A combination of $r$ objects taken out of $n$ objects is a subset of $r$ objects of a set of $n$ objects.
The number of combinations of $n$ different objects taken $r$ at a time is denoted by ${ }^{n} C_{r}$ or $C(n, r)$ or $\binom{n}{r}$ and is given by ${ }^{n} C_{r}=\frac{n!}{r!(n-r)!}$.
Theorem. Prove that ${ }^{n} C_{r}=\frac{n!}{r!(n-r)!}$.
Proof: Elements of a subset of $r$ objects of a set of $n$ objects can be arranged among themselves in $r$ ! ways. So, each combination will give rise to $r$ ! permutation. Thus, there will be ${ }^{n} C_{r} \times r$ ! permutations of $n$ different objects taken $r$ at a time that is:

$$
\begin{aligned}
& { }^{n} C_{r} \times r!={ }^{n} P_{r} \\
& \Rightarrow \quad{ }^{n} C_{r} \times r!=\frac{n!}{(n-r)!} \quad \therefore \quad{ }^{n} C_{r}=\frac{n!}{r!(n-r)!}
\end{aligned}
$$

Which completes the proof.

## Corollary:

(i) If $r=n$, then ${ }^{n} C_{n}=\frac{n!}{n!(n-n)!}=\frac{n!}{n!0!}=1$
(ii) If $r=0$, then ${ }^{n} C_{0}=\frac{n!}{0!(n-0)!}=\frac{n!}{0!n!}=1$

## Remember!

The formulae ${ }^{n} P_{r}$ and ${ }^{n} C_{r}$ are also known as counting formulae. Because, they are used to count the possible number of ways without listing them all.

# 7.4.1 Applications of Combination in Real Life 

Example 9 Zain has 8 different fruits. He wants to select 5 fruits out of 8 fruits to make a fruit chat. How many combinations of fruits he can select?
Solution To solve this problem, we have to find the number of combinations of 5 fruits out of 8 fruits. In this situation, $n=8$ and $r=5$.

$$
\begin{aligned}
{ }^{n} C_{r} & =\frac{n!}{r!(n-r)!} \\
\text { After putting values } \\
\begin{aligned}
{ }^{8} C_{3} & =\frac{8!}{5!(8-5)!}=\frac{8!}{5!\cdot 3!} \\
& =\frac{8 \times 7 \times 6 \times 5!}{5!\cdot 3!}=\frac{8 \times 7 \times 6}{3 \cdot 2 \cdot 1} \\
& =8 \times 7=56 \text { ways }
\end{aligned}
$$

Zain has 56 different ways to select 5 different fruits to make a fruit chat.
Example10 In a school, a class consists of 12 girls and 8 boys. The teacher wants to select 5 students for an activity. In how many ways can the students be selected including? (i) 2 girls
(ii) 5 boys
(iii) 2 boys

| Solution | Number of girls $=12$ | Challenge! |
| :--: | :--: | :--: |
|  | Number of boys $=8$ | A restaurant offers 6 flavours of pizza. How many ways are there to select 2 flavours of pizza? |

(i) Now let's find the total number of ways to select students when exactly 2 are girls.
${ }^{12} C_{2}{ }^{8} C_{3}=\frac{12!}{2!10!} \cdot \frac{8!}{3!5!}=\frac{12 \cdot 11 \cdot 10!}{2 \cdot 10!} \cdot \frac{8 \cdot 7 \cdot 6 \cdot 5!}{3 \cdot 2 \cdot 1 \cdot 5!}=3696$
(ii) Let's find total number of ways to select students when exactly 5 students are boys.

$$
{ }^{8} C_{3}=\frac{8!}{5!(8-5)!}=\frac{8!}{5!3!}=\frac{8 \cdot 7 \cdot 6 \cdot 5!}{5!3 \cdot 2 \cdot 1}=56
$$

(iii) Let's find total number of ways to select students when exactly 2 students are boys.

$$
{ }^{8} C_{2}{ }^{12} C_{3}=\frac{8!}{2!6!} \cdot \frac{12!}{3!9!}=\frac{8 \cdot 7 \cdot 6!}{2 \cdot 6!} \cdot \frac{12 \cdot 11 \cdot 10 \cdot 9!}{3 \cdot 2 \cdot 1 \cdot 9!}=36960
$$

### 7.4.2 Complementary Combinations

Theorem. Prove that: ${ }^{n} C_{r}={ }^{n} C_{n-r}$
Proof: If from $n$ different objects, we select $r$ objects then $(n-r)$ objects are left. Corresponding to every combination of $r$ objects, there is a combination of $(n-r)$

objects and vice versa. Thus, the number of combinations of $n$ objects taken $r$ at a time is equal to the number of combinations of $n$ objects taken $(n-r)$ at a time.

$$
\begin{aligned}
\therefore \quad{ }^{n} C_{r} & ={ }^{n} C_{n-r} \\
{ }^{n} C_{n-r} & =\frac{n!}{(n-r)!(n-n+r)!} \\
& =\frac{n!}{r!(n-r)!} \\
{ }^{n} C_{n-r} & ={ }^{n} C_{r}
\end{aligned}
$$

Note
This result will be found useful in evaluating
${ }^{n} C_{r}$ when $r>\frac{n}{2}$.
For example,
${ }^{12} C_{10}={ }^{12} C_{12-10}={ }^{12} C_{2}=\frac{(12) \cdot(11)}{2}=6 \cdot 11=66$

Note
${ }^{n} C_{r}$ and ${ }^{n} C_{n-r}$ are known as complementary combinations.
Example 11 Find the number of the diagonals of a 6 -sided figure.
Solution A 6 -sided figure has 6 vertices. By joining any two vertices, we get a line segment.
$\therefore \quad$ Number of line segments $={ }^{6} C_{2}=\frac{6!}{2!4!}=15$
But these line segments include 6 sides of the figure
$\therefore \quad$ number of diagonals $=15-6=9$
Difference between permutation and combination

| Permutation | Combination |
| :--: | :--: |
| - Order is important. <br> e.g., $a b$ and $b a$ are different (because order of any object is matter) | - Order is not important <br> e.g., $a b$ and $b a$ are same (because order does not matter) |
| - Arrangement of objects <br> e.g. arrangement of: | - Selection of objects <br> e.g. selection of: <br> - different colours <br> - members in a team <br> - food items |
| - ball of different colours <br> - English alphabet (letters) <br> - people while sitting on chairs |  |

# Application of Permutations and Combinations in Cryptography 

Example 12 Zain wants to generate a password for his laptop to secure the data. He can take only 6 characters to generate a password. Each character can either be an upper case letter $(A-Z)$ or digits from $(0-9)$.
Can you tell how many passwords can be generated by using the above letters and digits:
(i) if repetition of characters is not allowed
(ii) if repetition of characters is allowed

Solution
Total number of letters $=26$
Total number of digits $=10$
Total number of letters and digits $=26+10=36$
$n=$ total number of characters $=36$
$r=$ required number of characters $=6$
(i) If repetition of characters is not allowed, we find out total possible permutations as.

$$
\begin{aligned}
{ }^{n} P_{r}={ }^{36} P_{0} & =\frac{36!}{(36-6)!}=\frac{36!}{30!} \\
& =\frac{36 \cdot 35 \cdot 34 \cdot 33 \cdot 32 \cdot 31 \cdot 30!}{30!} \\
& =36 \cdot 35 \cdot 34 \cdot 33 \cdot 32 \cdot 31 \\
& =1,402,410,240 \text { ways }
\end{aligned}
$$

Hence, $1,402,410,240$ passwords can be generated by using the 26 alphabet and 10 digits. (If repetition of the characters is not allowed)
(ii) If the repetition of the characters is allowed Using fundamental principle of counting:
The total number of possible combinations $=36 \times 36 \times 36 \times 36 \times 36 \times 36=36^{6}$ Hence, $36^{6}$ passwords can be generated by using the 26 alphabets and 10 digits, If repetition of characters is allowed.
Application of permutations to estimate the odd of winning the lottery.
Example 13 A box contains 15 cards from ( $1-15$ ). Danish is to select 5 cards. If all the selected cards are the first five multiples of 2 then Danish will win the game. Find Danish's chance of winning the game, when
(i) order is important
(ii) order is not important

Solution $n=$ total number of cards $=15$
$r=$ required number of cards $=5$
(i) When order is important,

$$
\begin{aligned}
\text { Total possible ways } & ={ }^{n} P_{r}={ }^{15} P_{0}=\frac{15!}{(15-5)!} \\
& =\frac{15!}{10!}=360,360 \text { ways }
\end{aligned}
$$

Hence, Danish's chance to win the game $=\frac{1}{360,360}=0.000002775$

(ii) When order is not important

$$
\begin{aligned}
& n=\text { Total number of cards }=15 \\
& r=\text { Required number of cards }=5
\end{aligned}
$$

Total possible ways $={ }^{a} C_{r}={ }^{15} C_{5}=\frac{15!}{5!(15-5)!}$

$$
\begin{aligned}
& =\frac{15!}{5!10!}=\frac{15 \times 14 \times 13 \times 12 \times 11 \times 10!}{51.10!} \\
& =\frac{15 \times 14 \times 13 \times 12 \times 11}{5 \times 4 \times 3 \times 2 \times 1}=3003 \text { ways }
\end{aligned}
$$

Hence, Danish's chance to win the game $=\frac{1}{3003}=0.00033$
Application of Permutation and Combination to choose different sets of songs for Certain Occasions
Example 14 On Independence Day, a DJ has a list of ten different national songs. He wants to select any five national songs for the day. Find how many ways he can select and play the songs:
(i) if the order of playing the songs matters
(ii) if the order of playing the songs does not matter

Solution (i) When order matters

$$
\begin{aligned}
& n=\text { total number of national songs }=10 \\
& r=\text { required number of national songs }=5
\end{aligned}
$$

Total number of ways $={ }^{a} P_{1}={ }^{10} P_{5}$

$$
=\frac{10!}{(10-5)!}=\frac{10!}{5!}=30,240 \text { ways }
$$

Hence, the DJ can play the five national songs in 30,240 different ways.
(ii) When order is not matter
$n=$ total number of national songs $=10$
$r=$ total number of selected national songs $=5$

$$
\begin{aligned}
\text { Total number of ways } & ={ }^{a} C_{r}={ }^{10} C_{5}=\frac{10!}{5!(10-5)!} \\
& =\frac{10!}{51.5!}=252 \text { ways }
\end{aligned}
$$

Hence, the DJ can play the five national songs in 252 different ways.

# EXERCISE 7.4 

1. Evaluate the following:
(i) ${ }^{20} C_{50}$
(ii) ${ }^{1000} C_{0}$
(iii) ${ }^{10} C_{7}$
(iv) ${ }^{20} C_{17}$
2. (i) If ${ }^{34} C_{2}:{ }^{4} C_{2}=15: 1$, find $n$. (ii) If ${ }^{8} P_{r}=120$ and ${ }^{n} C_{r}=20$, find $r$.
3. Find the values of $n$ and $r$, when
(i) ${ }^{n} C_{r}=56,{ }^{n} P_{r}=336$
(ii) ${ }^{n-1} C_{r-1}:{ }^{n} C_{r}:{ }^{n} C_{r}=1: 3: 7$
4. Prove that (i) ${ }^{4} C_{r}+{ }^{4} C_{r-1}={ }^{n+1} C_{r}$
(ii) $r \cdot{ }^{4} C_{r}=(n-r+1){ }^{4} C_{r-1}$
5. Prove that product or $r$ consecutive intergers is divisible by $r^{1}$.
6. In how many ways can five subjects be selected out of eight subjects to select a course programme?
7. Find the number of possible arrangements of vowel letters from the English alphabet?
8. In how many ways 3 dishes of Desi foods and 2 dishes of Chinese foods be selected from 6 dishes of desi foods and 8 dishes of Chinese foods?
9. From a standard deck of 52 playing cards, there are 26 black cards and 26 red cards. How many different ways can eight cards be selected if 3 are black and the remaining 5 are red?
10. A bag contains 8 red balls and 7 green balls. Find the total number of possible ways in which five balls are selected in a way:
(i) 3 red and 2 green
(ii) 1 red and 4 green
(iii) 4 red and 1 green
(iv) all the red balls
11. How many diagonals and triangles can be formed by joining the vertices of the polygon having 15 sides.
12. Find the number of sides of a polygon if the number of its diagonals is 104.
13. How many triangles can be formed by joining 15 points, 6 of which lie on the same straight line?
14. The members of a club are 10 boys and 8 girls. In how many ways can a committee of 6 boys and 3 girls be formed?
15. How many committees of 7 members can be chosen from a group of 10 persons when each committee must include 2 particular persons?
16. In how many ways can a cricket team of 11 players be selected out of 17 players? How many of them will include a particular player?

17. There are 6 men and 8 women members of a club. How many committees of seven can be formed:
(i) with 3 women
(ii) with at most 3 women
(iii) with at least 5 women
18. There are three sections in a question paper; each section has 3 questions. A student has to solve all 5 questions, choosing at least one question from each section. In how many ways can the student make his choice?
19. Consider a cryptographic system that generates an 8 -character password. Each character in the password can be either a lowercase letter ( $a \sim f$ ) or a digit ( $0-5$ ). How many passwords can be generated if each password must contain exactly 5 lowercase letters and 3 digits:
(a) with repetition allowed
(b) without repetition
20. On Defense Day, Teacher I compiles a list of 10 distinct national songs, while Teacher II prepares a separate list of 10 different national songs (with no overlap between the two lists). The principal needs to select 3 songs from Teacher I's list, and 3 songs from Teacher II's list.
Determine the number of possible selection methods when:
(i) the order/sequence of the selected songs is important.
(ii) the order/sequence of the selected songs is not important.

# Mathematical Inductions and Binomial Theorem 

## INTRODUCTION

Francesco Mourolico (1494-1575) devised the method of induction and applied this device first to prove that the sum of the first $n$ odd positive integers equals $n^{2}$. He presented many properties of integers and proved some of these properties using the method of mathematical induction. In theoretical computer science, it bears the pivotal role of developing the appropriate cognitive skills necessary for the effective design and implementation of algorithms, assessing for both their correctness and complexity. We are aware of the fact that even one exception or case to a mathematical formula is enough to prove it to be false. Such a case or exception which fails the mathematical formula or statement is called a counter example.
The validity of a formula or statement depending on a variable belonging to a certain set is established if it is true for each element of the set under consideration.
For example, we consider the statement $S(n)=n^{2}-n+41$ is a prime number for every natural number $n$. The values of the expression $n^{2}-n+41$ for some first natural numbers are given in the table as shown below:

| $n$ | 1 | 2 | 3 | 4 | 5 | 6 | 7 | 8 | 9 | 10 | 11 |
| :--: | :--: | :--: | :--: | :--: | :--: | :--: | :--: | :--: | :--: | :--: | :--: |
| $S(n)$ | 41 | 43 | 47 | 53 | 61 | 71 | 83 | 97 | 113 | 131 | 151 |

From the table, it appears that the statement $S(n)$ has enough chance of being true. If we go on trying for the next natural numbers, we find $n=41$ as a counter example which fails the claim of the above statement. So we conclude that to derive a general formula without proof from some special cases is not a wise step. This example was discovered by Euler (1707-1783).
Now we consider another example and try to formulate the result. Our task is to find the sum of the first $n$ odd natural numbers. We write first few sums to see the pattern of sums.

| Unit 4 Mathematical Inductions and Binomial Theorem | $<141$ | Mathematics (1) |
| :--: | :--: | :--: |
| $n$ (The number of terms) | Sum |  |
| 1 | $1=1^{2}$ |  |
| 2 | $1+3=4=2^{2}$ |  |
| 3 | $1+3+5=9=3^{2}$ |  |
| 4 | $1+3+5+7=16=4^{2}$ |  |
| 5 | $1+3+5+7+9=25=5^{2}$ |  |
| 6 | $1+3+5+7+9+11=36=6^{2}$ |  |

The sequence of sums is $(1)^{2},(2)^{2},(3)^{2},(4)^{2}, \ldots$
We see that each sum is the square of the number of terms in the sum. So the following statement seems to be true.
For each natural number $n$,

$$
1+3+5+\cdots+(2 n-1)=n^{2} \ldots \text { (i) } \quad \because \quad n^{\text {th }} \text { term }=1+2(n-1)
$$

But it is not possible to verify the statement (i) for each positive integer $n$, because it involves infinitely many calculations which never end.
The method of mathematical induction is used to avoid such situations. Usually it is used to prove the statements or formulae relating to the set $\{1,2,3, \ldots\}$ but in some cases, it is also used to prove the statements relating to the set $\{0,1,2,3, \ldots\}$.
Hypothesis: A hypothesis is an educated guess or proposed explanation for a statement based on limited evidence. It serves as a starting point for further investigation and can be tested through experiments and observations. In scientific research, a hypothesis is usually framed as a statement that can be tested and either supported or rejected by data.
Induction of Hypothesis: It refers to the process of formulating a general statement or hypothesis based on specific examples or patterns observed in particular cases. This technique is often employed in mathematical reasoning to propose conjectures that can later be proven rigorously using deductive methods.

# 8.1 Principle of Mathematical Induction 

The principle of mathematical induction is stated as follows:
If a proposition or statement $S(n)$ for each positive integer $n$ is such that

1. Base Case: $S(1)$ is true i.e., $S(n)$ is true for $n=1$.
2. Induction of Hypothesis: $S(k+1)$ is true whenever $S(k)$ is true for any positive integer $k$.
3. Conclusion: $S(n)$ is true for all positive integers.

Procedure for Induction of Hypothesis

- Substituting $n=1$, show that the statement is true for $n=1$.
- Assuming that the statement is true for any positive integer $k$, then show that it is true for the next higher integer.
For the second condition, one of the following two methods can be used:
$S(k+1)$ is proved using $S(k)$.
$S(k+1)$ is established by performing algebraic operations on $S(k)$.
Example 1 Use mathematical induction to prove that $3+6+9+\ldots+3 n=\frac{3 n(n+1)}{2}$ for every positive integer $n$.
Solution Let $S(n)$ be the given statement, that is,

$$
S(n): 3+6+9+\ldots+3 n=\frac{3 n(n+1)}{2}
$$

Base Case: When $n=1, S(1): 3=\frac{3(1)(1+1)}{2}=3$. Thus $S(1)$ is true i.e., The base case is satisfied.
Induction of Hypothesis: Let us assume that $S(n)$ is true for any $n=k \in N$, that is,

$$
S(k): 3+6+9+\ldots+3 k \approx \frac{3 k(k+1)}{2}
$$

The statement for $n=k+1$ becomes

$$
\begin{aligned}
3+6+9+\ldots+3 k+3(k+1) & =\frac{3(k+1)[(k+1)+1]}{2} \\
& =\frac{3(k+1)(k+2)}{2}
\end{aligned}
$$

Adding $3(k+1)$ on both the sides of (A) gives

$$
\begin{aligned}
3+6+9+\ldots+3 k+3(k+1) & =\frac{3 k(k+1)}{2}+3(k+1) \\
& =3(k+1)\left(\frac{k}{2}+1\right) \\
& =\frac{3(k+1)(k+2)}{2}
\end{aligned}
$$

Thus $S(k+1)$ is true if $S(k)$ is true.
Conclusion: Since both the conditions are satisfied, therefore, $S(n)$ is true for each positive integer $n$.

Example 2 Use mathematical induction to prove that for any positive integer $n$,

$$
1^{2}+2^{2}+3^{2}+\ldots+n^{2}=\frac{n(n+1)(2 n+1)}{6}
$$

Solution Let $S(n)$ be the given statement,

$$
S(n): 1^{2}+2^{2}+3^{2}+\ldots+n^{2}=\frac{n(n+1)(2 n+1)}{6}
$$

Base Case: If $n=1, S(1):(1)^{2}=\frac{1(1+1)(2 \times 1+1)}{6}=\frac{1 \times 2 \times 3}{6}=1$, which is true. Thus $S(1)$ is true, i.e., The base case is satisfied.
Induction of Hypothesis: Let us assume that $S(k)$ is true for any $k \in N$, that is,

$$
\begin{aligned}
S(k): 1^{2}+2^{2}+3^{2}+\ldots+k^{2} & =\frac{k(k+1)(2 k+1)}{6} \\
S(k+1): 1^{2}+2^{2}+3^{2}+\ldots+k^{2}+(k+1)^{2} & =\frac{(k+1)(k+1+1)(2 k+1+1)}{6} \\
& =\frac{(k+1)(k+2)(2 k+3)}{6}
\end{aligned}
$$

Adding $(k+1)^{2}$ to both the sides of equation (4), we have

$$
\begin{aligned}
1^{2}+2^{2}+3^{2}+\ldots+k^{2}+(k+1)^{2} & =\frac{k(k+1)(2 k+1)}{6}+(k+1)^{2} \\
& =\frac{(k+1)[k(2 k+1)+6(k+1)]}{6} \\
& =\frac{(k+1)\left(2 k^{2}+k+6 k+6\right)}{6} \\
& =\frac{(k+1)\left(2 k^{2}+7 k+6\right)}{6} \\
& =\frac{(k+1)(k+2)(2 k+3)}{6}
\end{aligned}
$$

Thus, formula holds for $k+1$.
Conclusion: Since both the conditions are satisfied, therefore, by mathematical induction, the given statement holds for all positive integers.
Example 3 Show that $\frac{n^{2}+2 n}{3}$ represents an integer $\forall n \in N$.
Solution Let $S(n)=\frac{n^{2}+2 n}{3} \in Z \forall n \in N$
Base Case: When $n=1, S(1)=\frac{1^{2}+2(1)}{3}=\frac{3}{3}=1 \in Z$. The base case is satisfied.

Induction of Hypothesis: Let us assume that $S(n)$ is true for any $n=k \in N$, that is,

$$
S(k)=\frac{k^{2}+2 k}{3} \text { represents an integer. }
$$

Now we want to show that $S(k+1)$ is also an integer. For $n=k+1$, the statement becomes

$$
\begin{aligned}
S(k+1) & =\frac{(k+1)^{3}+2(k+1)}{3} \\
& =\frac{k^{3}+3 k^{2}+3 k+1+2 k+2}{3}=\frac{\left(k^{3}+2 k\right)+\left(3 k^{3}+3 k+3\right)}{3} \\
& =\frac{\left(k^{3}+2 k\right)+3\left(k^{2}+k+1\right)}{3}=\frac{k^{3}+2 k}{3}+\left(k^{2}+k+1\right)
\end{aligned}
$$

As $\frac{k^{3}+2 k}{3}$ is an integer by assumption and we know that $\left(k^{2}+k+1\right)$ is an integer as $k \in N . S(k+1)$ being sum of integers is an integer. Thus statements holds for $k+1$.
Conclusion: Since both the conditions are satisfied, therefore, we conclude by mathematical induction that $\frac{n^{2}+2 n}{3}$ represents an integer for all positive integral values of $n$.
Example 4 Use mathematical induction to prove that

$$
3+3 \cdot 5+3 \cdot 5^{2}+\cdots+3 \cdot 5^{n}=\frac{3\left(5^{n+1}-1\right)}{4} \text {, whenever } n \text { is non-negative integer. }
$$

Solution Let $S(n)$ be the given statement, that is,

$$
S(n): 3+3 \cdot 5+3 \cdot 5^{2}+\cdots+3 \cdot 5^{n}=\frac{3\left(5^{n+1}-1\right)}{4}
$$

The dot (.) between two numbers stands for multiplication symbol.

Base Case: For $n=0, S(0): 3 \cdot 5^{0}=\frac{3\left(5^{0+1}-1\right)}{4}$ or $3=\frac{3(5-1)}{4}=3$
Thus $S(0)$ is true i.e., The base case is satisfied.
Induction of Hypothesis: Let us assume that $S(k)$ is true for any $k \in W$, that is,

$$
S(k): 3+3 \cdot 5+3 \cdot 5^{2}+\cdots+3.5^{k}=\frac{3\left(5^{k+1}-1\right)}{4}
$$

Here $S(k+1)$ becomes

$$
\begin{aligned}
S(k+1): 3+3 \cdot 5+3 \cdot 5^{2}+\cdots+3 \cdot 5^{k}+3 \cdot 5^{k-1} & =\frac{3\left(5^{(k+1)+1}-1\right)}{4} \\
& =\frac{3\left(5^{k+2}-1\right)}{4}
\end{aligned}
$$

Adding $3.5^{k+1}$ on both sides of (A), we get

$$
\begin{aligned}
3+3 \cdot 5+3 \cdot 5^{2}+\cdots+3 \cdot 5^{k}+3 \cdot 5^{k+1} & =\frac{3\left(5^{k+1}-1\right)}{4}+3.5^{k+1} \\
& =\frac{3\left(5^{k+1}-1+4.5^{k+1}\right)}{4} \\
& =\frac{3\left[5^{k+1}(1+4)-1\right]}{4}=\frac{3\left(5^{k+2}-1\right)}{4}
\end{aligned}
$$

This shows that $S(k+1)$ is true when $S(k)$ is true.
Conclusion: Since both the conditions are satisfied, therefore, by the principle of mathematical induction, $S(n)$ in true for each $n \in W$.
Example 5 Prove that $4^{n}+6 n-1$ is divisible by 9 for all $n \in N$
Solution Let $S(n)$ be the given statement,

$$
S(n)=4^{n}+6 n-1 \text { is divisible by } 9 \text { for all } n \in N
$$

Base Case: Put $n=1, S(1)=4^{1}+6(1)-1=4+6-1=9$
Which is divisible by 9 . Hence it is true for $n=1$.
Induction of Hypothesis: Suppose the statement is true for $n=k$. i.e., $S(k)=4^{k}+6 k-1$ is divisible by 9
This implies $S(k)=4^{k}+6 k-1=9 k$, for some integer $k_{1}$

$$
4^{k}+6 k-1=9 k
$$

Now put $n=k+1$,

$$
\begin{aligned}
S(k+1) & =4^{k+1}+6(k+1)-1=4 \cdot 4^{k}+6 k+6-1 \\
& =4\left(9 k_{1}-6 k+1\right)+6 k+6-1 \\
& =36 k_{1}-24 k+4+6 k+5 \\
& =36 k_{1}-18 k+9 \\
& =9\left(4 k_{1}-2 k+1\right)
\end{aligned}
$$

Which is divisible by 9 .
Thus $S(k)$ is true for $n=k+1$.
Conclusion: Since both the conditions are satisfied, therefore, by the principle of mathematical induction, the given statement is true for all integers $n \geq 1$.
Example 6 Use mathematical induction to prove that

$$
\sum_{k=1}^{n} \frac{1}{(2 k-1)(2 k+1)}=\frac{n}{2 n+1}, \text { whenever } n \text { is a positive integer. }
$$

Solution Let $S(n)$ be the given statement, that is,

$$
S(n): \sum_{k=1}^{n} \frac{1}{(2 k-1)(2 k+1)}=\frac{n}{2 n+1}
$$

Base Case: For $n=1, S(1): \sum_{k=1}^{1} \frac{1}{(2 k-1)(2 k+1)}=\frac{1}{2.1+1}$,

$$
\frac{1}{1 \cdot 3}=\frac{1}{2 \cdot 1+1} \Rightarrow \frac{1}{3}=\frac{1}{3}
$$

Thus $S(1)$ is true i.e., The base case is satisfied.
Induction of Hypothesis: Let us assume that $S(n)$ is true for $n=m$, that is,

$$
S(m): \sum_{k=1}^{m} \frac{1}{(2 k-1)(2 k+1)}=\frac{m}{2 m+1}
$$

Here $S(m+1)$ becomes

$$
\begin{aligned}
S(m+1): & \sum_{k=1}^{m+1} \frac{1}{(2 k-1)(2 k+1)}=\frac{m}{2 m+1}+\frac{1}{(2 m+1)(2 m+3)} \\
& =\frac{m(2 m+3)+1}{(2 m+1)(2 m+3)}=\frac{2 m^{2}+3 m+1}{(2 m+1)(2 m+3)}=\frac{(m+1)(2 m+1)}{(2 m+1)(2 m+3)} \\
& =\frac{m+1}{2 m+3}=\frac{m+1}{2 m+2+1}=\frac{m+1}{2(m+1)+1}
\end{aligned}
$$

This shows that $S(k+1)$ is true when $S(k)$ is true.
Conclusion: Since both the conditions are satisfied, therefore, by the principle of mathematical induction, $S(n)$ in true for each $n \in N$.

# 8.1.1 Principle of Extended Mathematical Induction 

Let $i$ be an integer. A formula or identity or statement $S(n)$ for $n \geq i$ is such that

1. Base Case: $S(i)$ is true and
2. Induction of Hypothesis: $S(k+1)$ is true whenever $S(k)$ is true for any integer $n \geq i$.
3. Conclusion: $S(n)$ is true for all integers $n \geq i$.

Example 7 Show that $1+3+5+\cdots+(2 n+5)=(n+3)^{2}$ for integral values of $n \geq-2$.

## Solution

Base Case: Let $S(n)$ be the given statement, then for $n=-2, S(-2)$ becomes,

$$
2(-2)+5=(-2+3)^{2} \text {, i.e., } 1=(1)^{2} \text { which is true. }
$$

Thus $S(-2)$ is true i.e., The base case is satisfied.
Induction of Hypothesis: Let the equation be true for any $n=k \in Z, k \geq-2$, so that $\mathrm{S}(k): 1+3+5+\cdots+(2 k+5)=(k+3)^{2}$

$S(k+1): 1+3+5+\ldots+(2 k+5)+(2 k+1+5)=(k+1+3)^{2}=(k+4)^{2}$
Adding $(2 k+1+5)=(2 k+7)$ on both sides of equation (A) we get,

$$
\begin{aligned}
1+3+5+\cdots+(2 k+5)+(2 k+7) & =(k+3)^{2}+(2 k+7) \\
& =k^{2}+6 k+9+2 k+7 \\
& =k^{2}+8 k+16=(k+4)^{2}
\end{aligned}
$$

The formula holds for $k+1$.
Conclusion: As both the conditions are satisfied, so we conclude that the $S(n)$ is true for all integers $n \geq-2$.
Example 8 Show that the inequality $4^{n}>3^{n}+4$ is true, for integral values of $n \geq 2$.
Solution Let $S(n)$ represents the given statement i.e., $S(n): 4^{n}>3^{n}+4$ for integral values of $n \geq 2$
Base Case: For $n=2, S(2)$ becomes
$S(2): 4^{3}>3^{3}+4$, i.e., $16>13$ which is true.
Thus $S(2)$ is true, i.e., The base case is satisfied.
Induction of Hypothesis: Let the statement be true for any $n=k(\geq 2) \in Z$, that is

$$
S(k): 4^{k}>3^{k}+4
$$

Multiplying both sides of inequality (A) by 4 , we get

$$
4.4^{k}>4\left(3^{k}+4\right)
$$

or

$$
4^{k+1}>(3+1) 3^{k}+16
$$

or

$$
4^{k+1}>3^{k+1}+4+3^{k}+12
$$

or

$$
4^{k+1}>3^{k+1}+4 \quad\left(\because 3^{k}+12>0\right)
$$

The inequality (B), The formula holds for $k+1$.
Conclusion: Since both the conditions are satisfied, therefore, by the principle of extended mathematical induction, the given inequality is true for all integers $n \geq 2$.
Example 9 If $a_{n}=2^{2^{n}}+1$, then for $n>1$, show that last digit of $a_{n}$ is 7 .
Solution We will prove the statement by mathematical induction.
Base case: For $n=2$
$a_{2}=2^{2^{2}}+1=2^{4}+1=17$. Clearly unit digit is 7 .
Inductive Hypothesis: Assume that $a_{k}=2^{2^{k}}+1=10 m+7$ where $k>1$ and $m$ is some positive integer.

Now, $a_{k+1}=2^{2^{k+1}}+1=2^{2^{k} \cdot 3}+1$

$$
\begin{aligned}
& =\left(2^{2^{k}}\right)^{2}+1=(10 m+6)^{2}+1 \\
& =100 m^{2}+120 m+36+1 \\
& =100 m^{2}+120 m+30+7 \\
& =10\left(10 m^{2}+12 m+3\right)+7
\end{aligned}
$$

Thus, last digit of $a_{n}$ is 7 for all $n>1$.
Conclusion: Since both the conditions are satisfied, therefore, by the principle of mathematical induction, the given statement is true for all integers $n>1$.

# 8.1.2 Real Life Application of Mathematical Induction 

Mathematical induction is a powerful method used to prove statements that are formulated for natural numbers. It is often used in mathematics to justify conclusions about sequences, series, and other constructs that involve integer values.
Example10 Faris starts a savings plan where he deposits 1,000 rupees into his bank account every month. Using mathematical induction, prove that the total amount saved after $n$ months is given by:

$$
S(n)=1000 \times n \text { rupees }
$$

where $n$ is a positive integer representing the number of months.
Solution Given statement $S(n)=1000 \times n$
Base Case: For $n=1$ : After the first month, Faris save 1000 rupees. Therefore, the total savings after one month is $1000 \times 1=1000$ rupees. The base case $S(1)$ holds true.
Induction of Hypothesis: Assume the statement is true for some positive integer $k$, i.e., after $k$ months, the total savings is $S(k)=1000 \times k$ rupees.
Now, prove that the statement holds for $k+1$ months: After $k+1$ months, you would save an additional Rs. 1000, so the total savings becomes: $S(k+1)=1000 \times k+1000$ $=1000 \times(k+1)$ rupees. Thus, if the statement holds for $k$, it also holds for $k+1$.
Justification and Communication: Using mathematical induction, we prove that saving Rs. 1000 monthly for $n$ months totals $1000 \times n$ rupees.
The base case $(n=1)$ holds, and assuming it's true for $k$ months, we show it for $k+1$. Thus, the statement is valid for all natural numbers $n$, making it reliable for real-life applications.
Example 11 Ali starts a daily exercise routine where each day he increases the number of push-ups he does by 2 . On the first day, he does 10 push-ups. Prove that after $n^{\text {th }}$ day, the total number of push-ups Ali has done is $n^{2}+9 n$
Solution Base Case: For $n=1$ : On the first day, Ali do 10 push-ups. Total push-ups $(1)^{2}+9(1)=10$. The base case $S(1)$ holds true.

Induction of Hypothesis: Assume the statement is true for some positive integer $k$, i.e., the total number of push-ups after k days is $S(k)=k^{2}+9 k$.

Now, prove it for $k+1$ days: On the $(k+1)$ th day, you do $10+2 \times k$ push-ups. The total after $k+1$ days becomes: $k^{2}+9 k+(10+2 k)=k^{2}+2 k+1+9 k+9$

$$
=(k+1)^{2}+9(k+1)
$$

The formula holds for $S(k+1)$.
Conclusion: By mathematical induction, the total number of push-ups after $n$ days is

$$
n^{2}+9 n
$$

Example 12 Suppose you aim to lose weight by reducing your calories intake by 50 calories each week. If you start at 2500 calories, prove that after $n$ weeks, your daily intake is $2500-50 n$ calories.
Solution Base Case: For $n=1$ : After 1 week, your intake is $2500-50=2450$ calories. The base case $S(1)$ holds true.
Induction of Hypothesis: Assume the statement is true for some positive integer $k$, i.e., after $k$ : weeks, your intake is $S(k): 2500-50 \mathrm{k}$ calories.

Now, prove it for $k+1$ weeks: After $\mathrm{k}+1$ weeks, your intake will be:

$$
2500-50 k-50=2500-50(k+1) \text { calories. The formula holds for } k+1
$$

Conclusion: By mathematical induction, your daily intake after $n$ weeks is $2500-50 n$ calories.

# EXERCISE 8.1 

1. Use mathematical induction to prove the following formulae for every positive integer $n$.
(i) $\log x^{2}=n \log x$, where $x$ is positive
(ii) $2+5+8+\ldots+(3 n-1)=\frac{n}{2}(3 n+1)$
(iii) $2+(2+5)+(2+5+8)+\cdots+\frac{n}{2}(3 n+1)=\frac{n}{4}(n+1)^{2}$
(iv) $2+6+18+\cdots+2 \times 3^{n-1}=3^{n}-1$
(v) $1 \times 3+2 \times 5+3 \times 7+\cdots+n \times(2 n+1)=\frac{n(n+1)(4 n+5)}{6}$
(vi) $\frac{1}{1 \times 2}+\frac{1}{2 \times 3}+\frac{1}{3 \times 4}+\cdots+\frac{1}{n(n+1)}=1-\frac{1}{n+1}$

(vii) $r+r^{2}+r^{3}+\cdots+r^{n}=\frac{r\left(1-r^{n}\right)}{1-r}, \quad(r \neq 1)$
(viii) $a+(a+d)+(a+2 d)+\cdots+[a+(n-1) d]=\frac{n}{2}[2 a+(n-1) d]$
(ix) $a_{n}=a_{1}+(n-1) d \quad$ when, $a_{1}, a_{1}+d, a_{1}+2 d, \ldots$ form an A.P.
(x) $a_{n}=a_{1} r^{n-1} \quad$ when $a_{1}, a_{1} r, a_{1} r^{2}, \ldots$ form a G.P.
(xi) $\binom{3}{3}+\binom{4}{3}+\binom{5}{3}+\cdots+\binom{n+2}{3}=\binom{n+3}{4}$
(xii) The sum of first $n$ odd natural numbers is $n^{2}$.
2. Prove by mathematical induction that for all positive integral values of $n$
(i) $n^{2}+n$ is divisible by 2
(ii) $5^{n}-2^{n}$ is divisible by 3
(iii) $8 \times 10^{n}-2$ is divisible by 6
3. Prove that $\sum_{i=1}^{n} r^{n}=\frac{r^{n+1}-1}{r-1}$, whenever $n$ is a positive integer.
4. $x-y$ is a factor of $x^{n}-y^{n}$ for all positive integral values of $n,(x \neq y)$.
5. $n!>2^{n}-1$ for integral values of $n \geq 4$.
6. $4^{n}>3^{n}+2^{n-1}$ for integral values of $n \geq 2$.
7. $1+n x \leq(1+x)^{n}$ for $n \geq 2$ and $x \geq-1$.
8. Aliza invests Rs. $1,000,000$ in a business that promises a $6 \%$ return compounded annually. Prove by mathematical induction that the amount of money after $n$ years is $1,000,000(1.06)$
9. A bank offers an investment with an annual interest rate $r$. If $P$ rupees are invested, the amount after $n$ years is given by: $A(n)=P(1+r)$
Prove by induction that this formula holds for all $n \geq 0$.
10. Sikander saves Rs. 500 in the first month and increases his savings by Rs. 500 every subsequent month. Using mathematical induction, determine whether his total savings will reach at least Rs. 12,000 after 24 months.
11. Prove by mathematical induction that if Ali takes a loan of Rs. 2,000,000 and pay Rs. 50,000 at the end of each year, the remaining balance after $n$ years is $R_{n}=2,000,000-50,000 n$.
12. If Salman start savings with Rs. 5,000 and saves an additional Rs. 1,000 at the end of every month, derive a formula $S(n)$ for his total savings after $n$ months. Prove the correctness of year formula using mathematical induction.

# 8.2 Binomial Theorem 

An algebraic expression consisting of two terms such as $a+x, x-2 y, a x+b$ etc., is called a binomial or a binomial expression.
We know by actual multiplication that

$$
\begin{aligned}
& (a+b)^{2}=a^{2}+2 a b+b^{2} \\
& (a+b)^{3}=a^{3}+3 a^{2} b+3 a b^{2}+b^{3}
\end{aligned}
$$

The right sides of (i) and (ii) are called binomial expansions of the binomial $a+b$ for the indices 2 and 3 respectively.
In general, the rule or formula for expansion of a binomial raised to any positive integral power $n$ is called the binomial theorem for positive integral index $n$.
For any positive integer $n$,

$$
\begin{aligned}
(a+b)^{n}= & \binom{n}{0} a^{n}+\binom{n}{1} a^{n-1} b+\binom{n}{2} a^{n-2} b^{2}+\cdots+\binom{n}{r-1} a^{n-(r-1)} b^{r-1} \\
& +\binom{n}{r} a^{n-r} b^{r}+\cdots+\binom{n}{n-1} a b^{n-1}+\binom{n}{n} b^{n}
\end{aligned}
$$

or briefly $(a+b)^{n}=\sum_{r=1}^{n}\binom{n}{r} a^{n-r} b^{r}$, where $a$ and $b$ are real numbers.
The rule of expansion given above is called the binomial theorem and it also holds if $a$ or $b$ is complex.
Now we prove the binomial theorem for any positive integer $n$, using the principle of mathematical induction.
Proof: Let $S(n)$ be the statement given above as (A).
Base Case: If $n=1$, we obtain $S(1):(a+b)^{1}=\binom{1}{0} a^{1}+\binom{1}{1} a^{1-1} b=a+b$ which is true.
The base case is satisfied.
Induction of Hypothesis: Let us assume that the statement is true for any $n=k \in N$, then

$$
\begin{aligned}
& S(k):(a+b)^{k}=\binom{k}{0} a^{k}+\binom{k}{1} a^{k-1} b+\binom{k}{2} a^{k-2} b^{2}+\cdots+\binom{k}{r-1} a^{k-(r-1)} b^{r-1}+\binom{k}{r} a^{k-r} b^{r} \\
& +\cdots+\binom{k}{k-1} a b^{k-1}+\binom{k}{k} b^{k} \\
& S(k+1):(a+b)^{k+1}=\binom{k+1}{0} a^{k+1}+\binom{k+1}{1} a^{k} \times b+\binom{k+1}{2} a^{k-1} \times b^{2}+\cdots \\
& +\binom{k+1}{r-1} a^{k-r+2} \times b^{r-1}+\binom{k+1}{r} a^{k-r+1} \times b^{r}+\cdots+\binom{k+1}{k} a \times b^{k}+\binom{k+1}{k+1} b^{k+1}
\end{aligned}
$$

Multiplying both sides of equation (B) by $(a+b)$, we have

$$
\begin{aligned}
& (a+b)(a+b)^{k}=(a+b)\left[\binom{k}{0} a^{k}+\binom{k}{1} a^{k-1} b+\binom{k}{2} a^{k-2} b^{2}+\cdots+\binom{k}{r-1} a^{k-r+1} b^{r-1}\right. \\
& \left.+\binom{k}{r} a^{k-r} b^{r}+\cdots+\binom{k}{k-1} a b^{k-1}+\binom{k}{k} b^{k}\right] \\
& =\left[\binom{k}{0} a^{k+1}+\binom{k}{1} a^{k} b+\binom{k}{2} a^{k-1} b^{2}+\cdots+\binom{k}{r-1} a^{k-r+2} b^{r-1}\right. \\
& \left.+\binom{k}{r} a^{k-r+1} b^{r}+\cdots+\binom{k}{k-1} a^{k} b^{k-1}+\binom{k}{k} a b^{k}\right] \\
& +\left[\binom{k}{0} a^{k} b+\binom{k}{1} a^{k-1} b^{2}+\binom{k}{2} a^{k-2} b^{2}+\cdots+\binom{k}{r-1} a^{k-r-1} b^{r}\right. \\
& \left.+\binom{k}{r} a^{k-r} b^{r+1}+\cdots+\binom{k}{k-1} a b^{k}+\binom{k}{k} b^{k+1}\right] \\
& =\binom{k}{0} a^{k+1}+\left[\binom{k}{1}+\binom{k}{0}\right] a^{k} b+\left[\binom{k}{2}+\binom{k}{1}\right] a^{k-1} b^{2}+\cdots \\
& +\left[\binom{k}{r}+\binom{k}{r-1}\right] a^{k-r+1} b^{r}+\cdots+\left[\binom{k}{k}+\binom{k}{k-1}\right] a b^{k}+\binom{k}{k} b^{k+1}
\end{aligned}
$$

As $\binom{k}{0}=\binom{k+1}{0},\binom{k}{k}=\binom{k+1}{k+1}$ and $\binom{k}{r}+\binom{k}{r-1}=\binom{k+1}{r}$ for $0 \leq r \leq k$

$$
\begin{aligned}
& \therefore \quad(a+b)^{k+1}=\binom{k+1}{0} a^{k+1}+\binom{k+1}{1} a^{k} b+\binom{k+1}{2} a^{k-1} b^{2}+\cdots \\
& +\binom{k+1}{r} a^{k-r+1} b^{r}+\cdots+\binom{k+1}{k} a b^{k}+\binom{k+1}{k+1} b^{k+1}
\end{aligned}
$$

We find that if the statement is true for $n=k$, then it is also true for $n=k+1$.
Conclusion: Hence, we conclude that the statement is true for all positive integral values of $n$.

## Note

$\left(\binom{n}{0},\binom{n}{1},\binom{n}{2} \ldots,\binom{n}{n}\right.$ are called the binomial coefficients.

The following points can be observed in the expansion of $(a+b)^{n}$
(i) The number of terms in the expansion is one greater than its index.
(ii) The sum of exponents of $a$ and $x$ in each term of the expansion is equal to its index.
(iii) The exponent of $a$ decreases from index to zero.

(iv) The exponent of $b$ increases from zero to index.
(v) The coefficients of the terms equidistant from beginning and end of the expansion are equal as $\binom{n}{r}=\binom{n}{n-r}$
(vi) The $(r+1)^{\text {th }}$ term in the expansion is $\binom{n}{r} a^{n-r} b^{r}$ and we denote it as $T_{r+1}$ i.e.,

$$
T_{r+1}=\binom{n}{r} a^{n-r} b^{r}
$$

As all the terms of the expansion can be found from it by putting $r=0,1,2, \cdots, n$, so we call it as the general term of the expansion.
Example 13 Expand $\left(\frac{a}{2}-\frac{2}{a}\right)^{6}$ and also find its general term.

Solution $\left(\frac{a}{2}-\frac{2}{a}\right)^{6}=\left(\frac{a}{2}+\left(\frac{-2}{a}\right)\right)^{6}$

$$
\begin{aligned}
& =\left(\frac{a}{2}\right)^{6}+\binom{6}{1}\left(\frac{a}{2}\right)^{2}\left(-\frac{2}{a}\right)+\binom{6}{2}\left(\frac{a}{2}\right)^{4}\left(-\frac{2}{a}\right)^{2}+\binom{6}{3}\left(\frac{a}{2}\right)^{3}\left(-\frac{2}{a}\right)^{3} \\
& +\binom{6}{4}\left(\frac{a}{2}\right)^{2}\left(-\frac{2}{a}\right)^{4}+\binom{6}{5}\left(\frac{a}{2}\right)\left(-\frac{2}{a}\right)^{3}+\left(-\frac{2}{a}\right)^{6} \\
& =\frac{a^{6}}{64}+6\left(\frac{a^{2}}{32}\right)\left(-\frac{2}{a}\right)+\frac{6 \cdot 5}{2 \cdot 1} \cdot \frac{a^{4}}{16} \cdot \frac{4}{a^{2}}+\frac{6 \cdot 5 \cdot 4}{3 \cdot 2 \cdot 1} \cdot \frac{a^{3}}{8} \cdot\left(-\frac{8}{a^{4}}\right)+\frac{6 \cdot 5}{2 \cdot 1} \cdot \frac{a^{2}}{4} \cdot \frac{16}{a^{4}} \\
& +6 \cdot \frac{a}{2}\left(-\frac{32}{a^{2}}\right)+\frac{64}{a^{6}} \\
& =\frac{a^{6}}{64}-\frac{3}{8} a^{4}+\frac{15}{4} a^{2}-20+\frac{60}{a^{2}}-\frac{96}{a^{4}}+\frac{64}{a^{6}}
\end{aligned}
$$

$T_{r+1}$, the general term is given by

$$
\begin{aligned}
T_{r+1}= & \binom{6}{r}\left(\frac{a}{2}\right)^{6-r}\left(-\frac{2}{a}\right)^{r}=\binom{6}{r} \frac{a^{6-r}}{2^{6-r}}(-1)^{r} \frac{2^{r}}{a^{r}} \\
& =(-1)^{r}\binom{6}{r} \frac{a^{6-r}}{2^{6-r}} \frac{a^{-r}}{2^{-r}}=(-1)^{r}\binom{6}{r} \frac{a^{6-2 r}}{2^{6-2 r}}=(-1)^{r}\binom{6}{r}\left(-\frac{a}{2}\right)^{6-2 r}
\end{aligned}
$$

Example 14 Evaluate $(9.9)^{5}$ using binomial theorem.
Solution $(9.9)^{5}=(10-0.1)^{5}$

$$
\begin{aligned}
& =(10)^{5}+5 \times(10)^{4} \times(-0.1)+10(10)^{3} \times(-0.1)^{2}+10(10)^{2} \times(-0.1)^{3} \\
& +5(10)(-0.1)^{4}+(-0.1)^{5} \\
& =100000-(0.5)(10000)+(10000)(0.01)+1000(-0.001)+50(0.0001)-0.00001 \\
& =100000-5000+100-1+0.005-0.00001 \\
& =100100.005-5001.00001 \\
& =95099.00499
\end{aligned}
$$

Example 15 Find the specified term in the expansion of $\left(\frac{3}{2} x-\frac{1}{3 x}\right)^{11}$;
(i) the term involving $x^{5}$
(ii) the fifth term
(iii) the sixth term from the end
(iv) coefficient of the term involving $x^{-1}$.

# Sointion 

(i) Let $T_{r+1}$ be the term involving $x^{5}$ in the expansion of $\left(\frac{3}{2} x-\frac{1}{3 x}\right)^{11}$, then

$$
\begin{aligned}
T_{r+1} & =\binom{11}{r}\left(\frac{3}{2} x\right)^{11-r}\left(-\frac{1}{3 x}\right)^{r} \\
& =\binom{11}{r} \frac{3^{11-r}}{2^{11-r}} x^{11-r} \cdot(-1)^{r} \cdot 3^{-r} x^{-r}=(-1)^{r} \cdot\binom{11}{r} \frac{3^{11-2 r}}{2^{11-r}} x^{11-2 r}
\end{aligned}
$$

As this term involves $x^{5}$, so the exponent of $x$ is 5 , that is,

$$
11-2 r=5 \text { or }-2 r=5-11 \Rightarrow r=3
$$

Thus $T_{4}$ involves $x^{5}$

$$
\begin{aligned}
\therefore T_{4} & =(-1)^{5}\binom{11}{3} \frac{3^{11-6}}{2^{11-3}} x^{11-6}=(-1) \frac{11 \cdot 10 \cdot 9}{3 \cdot 2 \cdot 1} \cdot \frac{3^{5}}{2^{6}} x^{5} \\
& =-\frac{165 \cdot 243}{256} x^{5}=-\frac{40095}{256} x^{5}
\end{aligned}
$$

(ii) Putting $r=4$ in $T_{r+1}$, we get $T_{5}$,

$$
\begin{aligned}
\therefore \quad T_{5} & =(-1)^{4}\binom{11}{4} \frac{3^{11-8}}{2^{11-4}} x^{11-8}=\frac{11 \cdot 10 \cdot 9 \cdot 8}{4 \cdot 3 \cdot 2 \cdot 1} \cdot \frac{3^{3}}{2^{7}} x^{5} \\
& =\frac{11 \cdot 10 \cdot 3}{1} \cdot \frac{27}{128} x^{5}=\frac{165 \cdot 27}{64} x^{5}=\frac{4455}{64} x^{5}
\end{aligned}
$$

(iii) The 6 th term from the end term will have $(11+1)-6$ that is, 6 terms before it, $\therefore$ It will be $(6+1)^{\text {th }}$ term, that is the $7^{\text {th }}$ term of the expansion.

$$
\begin{aligned}
\text { Thus } T_{7} & =(-1)^{6}\binom{11}{6} \frac{3^{11-12}}{2^{11-6}} x^{11-12}=\frac{11 \cdot 10 \cdot 9 \cdot 8 \cdot 7}{5 \cdot 4 \cdot 3 \cdot 2 \cdot 1} \cdot \frac{3^{-1}}{2^{5}} x^{-1} \\
& =\frac{11 \times 6 \times 7}{1} \cdot \frac{1}{3 \times 32} \cdot \frac{1}{x}=\frac{77}{16 x}
\end{aligned}
$$

(iv) $\frac{77}{16}$ is the coefficient of the term involving $x^{-1}$.

# 8.2.1 The Middle Term in the Expansion of $(a+b)^{n}$ 

In the expansion of $(a+b)^{n}$, the total number of terms is $n+1$
Case I: ( $\boldsymbol{n}$ is even) If $n$ is even then $n+1$ is odd, so $\left(\frac{n}{2}+\frac{1}{2}\right)^{1 / 2}$ term will be the only one middle term in the expansion.
Case II: ( $\boldsymbol{n}$ is odd) if $\boldsymbol{n}$ is odd then $\boldsymbol{n}+1$ is even so $\left(\frac{n+1}{2}\right)^{1 / 2}$ and $\left(\frac{n+3}{2}\right)^{1 / 2}$ terms of the expansion will be the two middle terms.

Example 16 Find the following in the expansion of $\left(\frac{x}{2}+\frac{2}{x^{3}}\right)^{12}$;
(i) the term independent of $x$
(ii) the middle term

Solution (i) Let $T_{r+1}$ be the term independent of $x$ in the expansion of

$$
\begin{aligned}
& \left(\frac{x}{2}+\frac{2}{x}\right)^{12}, \text { then } \\
& T_{r+1}=\binom{12}{r}\left(\frac{x}{2}\right)^{12-r}\left(\frac{2}{x^{3}}\right)^{r} \\
& =\binom{12}{r} \frac{x^{12-r}}{2^{12-r}} \cdot 2^{r} \cdot x^{-3 r}=\binom{12}{r} 2^{2 r-12} \cdot x^{12-3 r}
\end{aligned}
$$

As the term is independent of $x$, so exponent of $x$, will be zero.
That is, $\quad 12-3 r=0 \Rightarrow r=4$.
Therefore, the required term $\mathrm{T}_{5}=\binom{12}{4} 2^{8-12} x^{13-13}=\frac{12 \cdot 11 \cdot 10 \cdot 9}{4 \cdot 3 \cdot 2 \cdot 1} \cdot 2^{-4} x^{0}$

$$
=\frac{11 \times 45}{2^{4}}=\frac{495}{16}
$$

(ii) In this case, $n=12$ which is even, so $\left(\frac{12}{2}+1\right)^{\text {th }}$ term is the middle term.

$$
\begin{aligned}
T_{7} & =\binom{12}{6}\left(\frac{x}{2}\right)^{12-6} \cdot\left(\frac{2}{x^{2}}\right)^{6} \text { Because } T_{7} \text { is the required term. } \\
& =\binom{12}{6} \frac{x^{6}}{2^{6}} \cdot \frac{2^{6}}{x^{12}}=\frac{12 \times 11 \times 10 \times 9 \times 8 \times 7}{6 \times 5 \times 4 \times 3 \times 2 \times 1} \cdot x^{6-12} \\
& =\frac{12 \times 11 \times 7}{x^{6}}=\frac{924}{x^{6}}
\end{aligned}
$$

# 8.2.2 Some Deductions from the binomial expansion of $(a+b)^{n}$ 

We know that

$$
\begin{aligned}
(a+b)^{n}=\binom{n}{0} a^{n}+\binom{n}{1} a^{n-1} b+\binom{n}{2} & a^{n-2} b^{2}+\cdots \\
& +\binom{n}{r} a^{n-r} b^{r}+\cdots+\binom{n}{n-1} a b^{n-1}+\binom{n}{n} b^{n}
\end{aligned}
$$

(i) If we put $a=1$, in (A), then we have;

$$
\begin{aligned}
(1+b)^{n} & =\binom{n}{0}+\binom{n}{1} b+\binom{n}{2} b^{2}+\cdots+\binom{n}{r} b^{r}+\cdots+\binom{n}{n-1} b^{n-1}+\binom{n}{n} b^{n} \\
& =1+n b+\frac{n(n-1)}{2!} b^{2}+\cdots+\frac{n(n-1)(n-2) \cdots(n-r+1)}{r!} b^{r}+\cdots+n b^{n-1}+b^{n} \\
\because\left\{\left(\begin{array}{l}
n \\
r
\end{array}\right)\right. & =\frac{n!}{r!(n-r)!}=\frac{n(n-1) \cdots(n-r+1)(n-r)!}{r!(n-r)!}=\frac{n(n-1) \cdots(n-r-1)}{r!}
\end{aligned}
$$

(ii) Putting $a=1$ and replacing $b$ by $-b$, in (A), we get.

$$
\begin{aligned}
(1-b)^{n} & =\binom{n}{0}+\binom{n}{1}(-b)+\binom{n}{2}(-b)^{2}+\binom{n}{3}(-b)^{3}+\cdots+\binom{n}{n-1}(-b)^{n-1}+\binom{n}{n}(-b)^{n} \\
& =\binom{n}{0}-\binom{n}{1} b+\binom{n}{2} b^{2}-\binom{n}{3} b^{3}+\cdots+(-1)^{n-1}\binom{n}{n-1} b^{n-1}+(-1)^{n}\binom{n}{n} b^{n}
\end{aligned}
$$

(iii) We can find the sum of the binomial coefficients by putting $a=1$ and $b=1$ in (A).
i.e., $(1+1)^{n}=\binom{n}{0}+\binom{n}{1}+\binom{n}{2}+\cdots+\binom{n}{n-1}+\binom{n}{n}$
or $2^{n}=\binom{n}{0}+\binom{n}{1}+\binom{n}{2}+\cdots+\binom{n}{n-1}+\binom{n}{n}$
Thus, the sum of coefficients in the binomial expansion equals to $2^{n}$.

(iv) Putting $a=1$ and $b=-1$, in (A), we have

$$
(1-1)^{n}=\binom{n}{0}=\binom{n}{1}+\binom{n}{2}=\binom{n}{3}+\cdots+(-1)^{n-1}\binom{n}{n-1}+(-1)^{n}\binom{n}{n}
$$

Thus $\binom{n}{0}=\binom{n}{1}+\binom{n}{2}=\binom{n}{3}+\cdots+(-1)^{n-1}\binom{n}{n-1}+(-1)^{n}\binom{n}{n}=0$
If $n$ is odd positive integer, then

$$
\binom{n}{0}+\binom{n}{2}+\cdots+\binom{n}{n-1}=\binom{n}{1}+\binom{n}{3}+\cdots+\binom{n}{n}
$$

If $n$ is even positive integer, then

$$
\binom{n}{0}+\binom{n}{2}+\cdots+\binom{n}{n}=\binom{n}{1}+\binom{n}{3}+\cdots+\binom{n}{n-1}
$$

Thus, sum of odd coefficients of a binomial expansion equals to the sum of its even coefficients.
Example 17 Show that: $\binom{n}{1}+2\binom{n}{2}+3\binom{n}{3}+\cdots+n\binom{n}{n}=n \cdot 2^{n-1}$
Solution $\binom{n}{1}+2\binom{n}{2}+3\binom{n}{3}+\cdots+n\binom{n}{n}=n+2 \frac{n(n-1)}{2!}+3 \frac{n(n-1)(n-2)}{3!}+\cdots+n \cdot 1$

$$
\begin{aligned}
& =n\left[1+(n-1)+\frac{(n-1)(n-2)}{2!}+\cdots+1\right] \\
& =n\left[\binom{n-1}{0}+\binom{n-1}{1}+\binom{n-1}{2}+\cdots+\binom{n-1}{n-1}\right]=n \cdot 2^{n-1}
\end{aligned}
$$

# EXERCISE 8.2 

1. Using binqinal theorem, expand the following:
(i) $\left(\frac{x}{2}-\frac{2}{x^{2}}\right)^{4}$
(ii) $\left(2 a-\frac{x}{a}\right)^{7}$
(iii) $\left(\sqrt{\frac{a}{x}}-\sqrt{\frac{x}{a}}\right)^{6}$
2. Calculate the following by means of binomial theorem:
(i) $(0.97)^{3}$
(ii) $(2.02)^{4}$
(iii) $(9.98)^{4}$
(iv) $(2.1)^{5}$
3. Expand and simplify the following:
(i) $(a+\sqrt{2} x)^{4}+(a-\sqrt{2} x)^{4}$
(ii) $(2+\sqrt{3})^{5}+(2-\sqrt{3})^{5}$
4. Expand the following in ascending power of $x$ :
(i) $\left(2+x-x^{2}\right)^{4}$
(ii) $\left(1-x+x^{2}\right)^{4}$

5. Find the term involving:
(i) $x^{4}$ in the expansion of $(3-2 x)^{7}$
(ii) $x^{-2}$ in the expansion of $\left(x-\frac{2}{x^{2}}\right)^{13}$
(iii) $a^{4}$ in the expansion of $\left(\frac{2}{x}-a\right)^{9}$
(iv) $y^{3}$ in the expansion of $(x-\sqrt{y})^{11}$
6. Find the coefficient of;
(i) $x^{3}$ in the expansion of $\left(x^{2}-\frac{3}{2 x}\right)^{18}$
(ii) $x^{n}$ in the expansion of $\left(x^{2}-\frac{1}{x}\right)^{2 n}$
7. Find $6^{\text {th }}$ term in the expansion of $\left(x^{2}-\frac{3}{2 x}\right)^{10}$.
8. Find the term independent of $x$ in the following expansions;
(i) $\left(x-\frac{2}{x}\right)^{10}$
(ii) $\left(\sqrt{x}+\frac{1}{2 x^{2}}\right)^{10}$
(iii) $\left(1+x^{2}\right)^{3}\left(1+\frac{1}{x^{2}}\right)^{4}$
9. Determine the middle term in the following expansions:
(i) $\left(\frac{1}{x}-\frac{x^{2}}{2}\right)^{12}$
(ii) $\left(\frac{3}{2} x-\frac{1}{3 x}\right)^{11}$
(iii) $\left(2 x-\frac{1}{2 x}\right)^{2 m+1}$
10. Show that: $\binom{n}{1}+\binom{n}{2}+\binom{n}{3}+\ldots+\binom{n}{n}=2^{n}-1$

# 8.3 The Binomial Theorem (When the Index $n$ is a Negative Integer or a Fraction) 

When $n$ is a negative integer or a fraction, then

$$
\begin{aligned}
(1+x)^{n}=1+n x & +\frac{n(n-1)}{2!} x^{2}+\frac{n(n-1)(n-2)}{3!} x^{3}+\ldots \\
& +\frac{n(n-1)(n-2) \cdots(n-r+1)}{r!} x^{r}+\ldots
\end{aligned}
$$

provided $|x|<1$.
The series of the type $1+n x+\frac{n(n-1)}{2!} x^{2}+\frac{n(n-1)(n-2)}{3!} x^{3}+\ldots$ is called the binomial series.

## Note

- The proof of this theorem is beyond the scope of this book.
- Symbols $\binom{n}{0}\binom{n}{1}\binom{n}{2}$ etc are meaningless when $n$ is a negative integer or a fraction.
- The general term in the expansion is $T_{n 1}=\frac{n(n-1)(n-2) \cdots(n-r+1)}{r!} x^{r}$

Example 18 Find the general term in the expansion of $(1+x)^{-2}$ when $|x|<1$.
Solution

$$
\begin{aligned}
& T_{r+1}=\frac{(-3)(-4)(-5) \cdots(-3-r+1)}{r!} x^{r} \\
= & \frac{(-1)^{r} \cdot 3 \cdot 4 \cdot 5 \cdots(r+2)}{r!} x^{r} \quad=(-1)^{r} \frac{1 \cdot 2 \cdot 3 \cdot 4 \cdot 5 \cdots(r+2)}{1 \cdot 2 \cdot r!} x^{r} \\
= & (-1)^{r} \frac{r! \cdot(r+1)(r+2)}{2 \cdot r!} x^{r}=(-1)^{r} \frac{(r+1)(r-2)}{2} x^{r}
\end{aligned}
$$

Some particular cases of the expansion of $(1+x)^{n}, n<0$.
(i) $(1+x)^{-1}=1-x+x^{2}-x^{3}+\cdots+(-1)^{r} x^{r}+\cdots$
(ii) $(1+x)^{-2}=1-2 x+3 x^{2}-4 x^{3}+\ldots+(-1)^{r}(r+1) x^{r}+\cdots$
(iii) $(1+x)^{-3}=1-3 x+6 x^{2}-10 x^{3}+\cdots+(-1)^{r} \frac{(r+1)(r+2)}{2} x^{r}+\cdots$
(iv) $(1-x)^{-1}=1+x+x^{2}+x^{3}+\cdots+x^{r}+\cdots$
(v) $(1-x)^{-5}=1+2 x+3 x^{2}+4 x^{3}+\cdots+(r+1) x^{r}+\cdots$
(vi) $(1-x)^{-8}=1+3 x+6 x^{2}+10 x^{3}+\cdots+\frac{(r+1)(r+2)}{2} x^{r}+\cdots$

Example 19 Find the coefficient of $x^{n}$ in the expansion of $\frac{1-x}{(1+x)^{2}}$
Solution $\frac{1-x}{(1+x)^{2}}=(1-x)(1+x)^{-2}$

$$
\begin{aligned}
& =(-x+1)\left[1+(-2 x)+\frac{(-2)(-3)}{2!} x^{2}+\cdots+\frac{(-2)(-3) \cdots(-2-r+1)}{r!} x^{r}+\cdots\right] \\
& =(-x+1)\left[1+(-1) 2 x+(-1)^{2} 3 x^{2}+\cdots+(-1)^{r} \times(r+1) x^{r}+\cdots\right] \\
& =(-x+1)\left[1+(-1) 2 x+(-1)^{2} 3 x^{2}+\cdots+(-1)^{n-1} n x^{n-1}+(-1)^{n}(n+1) x^{n}+\cdots\right] \\
& \text { Coefficient of } x^{n}=(-1)(-1)^{n-1} n+(-1)^{n}(n+1) \\
& =(-1)^{n} n+(-1)^{n}(n+1)=(-1)^{n}[n+(n+1)]=(-1)^{n}(2 n+1)
\end{aligned}
$$

Example 20 If $x$ is so small that its cube and higher power can be neglected, show that $\sqrt{\frac{1-x}{1+x}} \approx 1-x+\frac{1}{2} x^{2}$
Solution $\sqrt{\frac{1-x}{1+x}}=(1-x)^{1 / 2}(1+x)^{-1 / 2}$

$$
=\left[1+\frac{1}{2}(-x)+\frac{\frac{1}{2}\left(\frac{1}{2}-1\right)}{2!}(-x)^{2}+\cdots\right]\left[1+\left(-\frac{1}{2}\right) x+\frac{\left(-\frac{1}{2}\right)\left(-\frac{1}{2}-1\right)}{2!} x^{2}+\cdots\right]
$$

$$
\begin{aligned}
& =\left[1-\frac{1}{2} x-\frac{1}{8} x^{2}+\ldots\right]\left[1-\frac{1}{2} x+\frac{3}{8} x^{2}+\cdots\right] \\
& =\left[\left(1-\frac{1}{2} x+\frac{3}{8} x^{2}\right)+\left(-\frac{1}{2} x+\frac{1}{4} x^{2}\right)-\frac{1}{8} x^{2}+\cdots\right] \\
& =1-\left(\frac{1}{2}+\frac{1}{2}\right) x+\left(\frac{3}{8}+\frac{1}{4}-\frac{1}{8}\right) x^{2}+\cdots \approx 1-x+\frac{1}{2} x^{2}
\end{aligned}
$$

Example:1 For $y=\frac{1}{2}\left(\frac{4}{9}\right)+\frac{1 \cdot 3}{2^{2} 2!}\left(\frac{4}{9}\right)^{2}+\frac{1.3 .5}{2^{3} 3!}\left(\frac{4}{9}\right)^{3}+\cdots$ show that $5 y^{2}+10 y-4=0$
Solution $y=\frac{1}{2}\left(\frac{4}{9}\right)+\frac{1.3}{4.2!}\left(\frac{4}{9}\right)^{2}+\frac{1.3 .5}{8.3!}\left(\frac{4}{9}\right)^{3}+\cdots$
Adding 1 to both sides of (A), we obtain

$$
1+y=1+\frac{1}{2}\left(\frac{4}{9}\right)+\frac{1 \cdot 3}{4 \cdot 2!}\left(\frac{4}{9}\right)^{2}+\frac{1 \cdot 3 \cdot 5}{8 \cdot 3!}\left(\frac{4}{9}\right)^{3}+\cdots
$$

Let the series on the right side of (B) be identical with

$$
1+n x+\frac{n(n-1)}{2!} x^{2}+\frac{n(n-1)(n-2)}{3!} x^{3}+\cdots
$$

which is the expansion of $(1+x)^{n}$ for $|x|<1$ and $n$ is not a positive integer.
By comparing terms of both the series, we get

$$
\begin{aligned}
n x & =\frac{1}{2}\left(\frac{4}{9}\right) \\
\frac{n(n-1)}{2!} x^{2} & =\frac{1 \cdot 3}{4 \cdot 2!}\left(\frac{4}{9}\right)^{2}
\end{aligned}
$$

From (i), $\quad x=\frac{2}{9 n}$
Substituting $x=\frac{2}{9 n}$ in (ii), we get
$\frac{n(n-1)}{2}\left(\frac{2}{9 n}\right)^{2}=\frac{3}{8} \cdot \frac{16}{81}$ or $\frac{n(n-1)}{2} \cdot \frac{4}{81 n^{2}}=\frac{3}{8} \cdot \frac{16}{81}$
or $\quad 2(n-1)=6 n \quad$ or $n-1=3 n \Rightarrow n=-\frac{1}{2}$

Putting

$$
n=-\frac{1}{2} \text { in (iii), we get } x=\frac{2}{9\left(-\frac{1}{2}\right)}=-\frac{4}{9}
$$

Thus

$$
1+y=\left(1-\frac{4}{9}\right)^{-1 / 2}=\left(\frac{5}{9}\right)^{-1 / 2}=\left(\frac{9}{5}\right)^{1 / 2}=\frac{3}{\sqrt{5}}
$$

or $\sqrt{5}(1+y)=3$
Squaring both the sides of (iv), we get

$$
5\left(1+2 y+y^{2}\right)=9 \quad \text { or } \quad 5 y^{2}+10 y-4=0
$$

# EXERCISE 8.3 

1. Expand the following upto 4 terms, taking the values of $x$ such that the expansion in each case is valid:
(i) $(1+x)^{-1 / 3}$
(ii) $(4-3 x)^{1 / 2}$
(iii) $\frac{(1-x)^{-1}}{(1+x)^{2}}$
(iv) $\frac{\sqrt{1+2 x}}{1-x}$
2. Find the coefficient of $x^{n}$ in the expansion of:
(i) $\frac{1+x^{2}}{(1+x)^{2}}$
(ii) $\frac{(1+x)^{2}}{(1-x)^{2}}$
3. If $x$ is so small that its square and higher powers can be neglected, then show that:
(i) $\frac{1-x}{\sqrt{1+x}} \approx 1-\frac{3}{2} x$
(ii) $\frac{\sqrt{1+2 x}}{\sqrt{1-x}} \approx 1+\frac{3}{2} x$
(iii) $\frac{(9+7 x)^{1 / 2}-(16+3 x)^{1 / 4}}{4+5 x} \approx \frac{1}{4}-\frac{17}{384} x$
(iv) $\frac{\sqrt{4+x}}{(1-x)^{2}} \approx 2+\frac{25}{4} x$
4. If $x$ is so small that its cube and higher power can be neglected, show that:
(i) $\sqrt{1-x-2 x^{2}} \approx 1-\frac{1}{2} x-\frac{9}{8} x^{2}$
(ii) $\sqrt{\frac{1+x}{1-x}} \approx 1+x+\frac{1}{2} x^{2}$
5. If $x$ is very nearly equal 1 , then prove that $p x^{p}-q x^{q} \approx(p-q) x^{p+q}$
6. Identify the following series as binomial expansion and find the sum.

$$
1-\frac{1}{2}\left(\frac{1}{4}\right)+\frac{1 \cdot 3}{2!4}\left(\frac{1}{4}\right)^{2}-\frac{1 \cdot 3 \cdot 5}{3!8}\left(\frac{1}{4}\right)^{3}+\cdots
$$

7. Use binomial theorem to show that $1+\frac{1}{4}+\frac{1 \cdot 3}{4 \cdot 8}+\frac{1 \cdot 3 \cdot 5}{4 \cdot 8 \cdot 12}+\cdots=\sqrt{2}$

8. If $y=\frac{1}{3}+\frac{1 \cdot 3}{2!}\left(\frac{1}{3}\right)^{2}+\frac{1 \cdot 3 \cdot 5}{3!}\left(\frac{1}{3}\right)^{3}+\cdots$ prove that $y^{2}+2 y-2=0$.
9. If $2 y=\frac{1}{2^{2}}+\frac{1 \cdot 3}{2!} \cdot \frac{1}{2^{4}}+\frac{1 \cdot 3 \cdot 5}{3!} \cdot \frac{1}{2^{6}}+\cdots$, prove that $4 y^{2}+4 y-1=0$
10. Show that the coefficient of $x^{r}$ in $\frac{x}{(1-p x)(1-q x)}$ is $\frac{p^{r}-q^{r}}{p-q}$.

# 8.4 Binomial Coefficients Using Pascal's Triangle 

Binomial coefficients arise in the binomial expansion of powers of a binomial expression, such as $(x+y)^{n}$. These coefficients are denoted by:

$$
\binom{n}{r}=\frac{n!}{r!(n-r)!}, \text { where } 0 \leq r \leq n
$$

Pascal's Triangle provides a combinatorial method to compute binomial coefficients without directly using factorials. The construction of Pascal's triangle follows these rules:

1. The first row (corresponding to $n=0$ ) consists of a single entry:1.
2. Each subsequent row begins and ends with 1 .
3. Every interior entry is the sum of the two entries directly above it from the previous row.
[Image removed]

Mathematically, this is expressed by Pascal's Rule:

$$
\text { Pascal's Rule: }\binom{n}{k}=\binom{n-1}{k-1}+\binom{n-1}{k}, \quad \text { for } 0<k<n
$$

The entries in the $n^{\text {th }}$ row of Pascal's Triangle correspond to the binomial coefficients $\binom{n}{0},\binom{n}{1}, \ldots,\binom{n}{n}$
For example, the binomial coefficients corresponding to $n=4$ are:

$$
\binom{4}{0}=1,\binom{4}{1}=4,\binom{4}{2}=6,\binom{4}{3}=4,\binom{4}{4}=1
$$

Example 22 Expand $(x+y)^{4}$ using Pascal's triangle.
Solution The binomial coefficients for the expansion of correspond to the entries in the $n=4$ row of Pascal's triangle: 14641
Thus, the binomial expansion using Pascal's triangle is

$$
\begin{aligned}
& (x+y)^{4}=1 x^{4}+4 x^{3} y+6 x^{2} y^{2}+4 x y^{3}+1 y^{4} \\
& (x+y)^{4}=x^{4}+4 x^{3} y+6 x^{2} y^{2}+4 x y^{3}+y^{4}
\end{aligned}
$$

Example 23 Expand $(x-2)^{5}$ use the binomial theorem and using Pascal's triangle.
Solution Expand using Binomial Theorem:

$$
\begin{aligned}
(x-2)^{5} & ={ }^{5} C_{0} x^{5}(-2)^{0}+{ }^{5} C_{1} x^{5-1}(-2)^{1}+{ }^{5} C_{2} x^{5-2}(-2)^{2}+{ }^{5} C_{3} x^{5-3}(-2)^{3} \\
& =x^{5}-10 x^{4}+40 x^{3}-80 x^{2}+80 x-32
\end{aligned}
$$

The binomial coefficients for the expansion of correspond to the entries in the $n=5$ row of Pascal's triangle: 15101051
$(a+b)^{5}={ }^{5} C_{0} a^{5} b^{0}+{ }^{5} C_{1} a^{4} b^{1}+{ }^{5} C_{2} a^{3} b^{2}+{ }^{5} C_{3} a^{2} . b^{3}+{ }^{5} C_{4} a^{1} b^{4}+{ }^{5} C_{5} a^{0} b^{5}$
Replace binomial coefficient from Pascal triangle and $a=x, b=-2$

$$
\begin{aligned}
(x-2)^{5} & =x^{5}(-2)^{0}+5 x^{4}(-2)^{1}+10 x^{3}(-2)^{2}+10 x^{2}(-2)^{3}+5 x(-2)^{4}+(-2)^{5} \\
& =x^{5}-10 x^{4}+40 x^{3}-80 x^{2}+80 x-32
\end{aligned}
$$

# 8.5 Applications of Binomial Theorem 

### 8.5.1 Finding Approximate Value Using Binomial Theorem

Approximations: We have seen in the particular cases of the expansion of $(1+x)^{n}$ that the power of $x$ goes on increasing in each expansion. Since $|x|<1$, so

$$
|x|^{r}<|x| \text { for } r=2,3,4, \ldots
$$

This fact shows that terms in each expansion go on decreasing numerically if $|x|<1$. Thus, some initial terms of the binomial series are enough for determining the approximate values of binomial expansions having indices as negative integers or fractions.
Summation of infinite series: The binomial series are conveniently used for summation of infinite series. The series (whose sum is required) is compared with

$$
1+n x+\frac{n(n-1)}{2!} x^{2}+\frac{n(n-1)(n-2)}{3!} x^{3}+\ldots
$$

to find out the values of $n$ and $x$. Then the sum is calculated by putting the values of $n$ and $x$ in $(1+x)^{n}$.

Example 24 Expand $(1-2 x)^{1 / 3}$ to four terms and apply it to evaluate $(0.8)^{1 / 3}$ correct to three places of decimal.
Solution This expansion is valid only if $|2 x|<1$ or $2|x|<1$ or $|x|<\frac{1}{2}$, that is

$$
\begin{aligned}
(1-2 x)^{1 / 3} & =1+\frac{1}{3}(-2 x)+\frac{\frac{1}{3}\left(\frac{1}{3}-1\right)}{2!}(-2 x)^{2}+\frac{\frac{1}{3}\left(\frac{1}{3}-1\right)\left(\frac{1}{3}-2\right)}{3!}(-2 x)^{3} \ldots \\
& =1-\frac{2}{3} x+\frac{\frac{1}{3}\left(-\frac{2}{3}\right)}{2.1}\left(4 x^{2}\right)+\frac{\frac{1}{3}\left(-\frac{2}{3}\right)\left(-\frac{5}{3}\right)}{3.2 .1}\left(-8 x^{3}\right) \ldots \\
& =1-\frac{2}{3} x-\frac{4}{9} x^{2}-\frac{1.2 .5}{3.3 .3} \cdot \frac{1}{3.2 .1}\left(8 x^{3}\right)-\ldots \\
& =1-\frac{2}{3} x-\frac{4}{9} x^{2}-\frac{40}{81} x^{3}-\ldots
\end{aligned}
$$

Putting $x=.1$ in the above expansion we have

$$
\begin{aligned}
(1-2(0.1))^{1 / 3} & =1-\frac{2}{3}(0.1)-\frac{4}{9}(0.1)^{2}-\frac{40}{81}(0.1)^{3}-\ldots \\
& =1-\frac{0.2}{3}-\frac{0.04}{9}-\frac{0.04}{81} \\
& \approx 1-0.06666-0.00444-0.00049=1-0.07159=0.92841
\end{aligned}
$$

Thus $(.8)^{1 / 3} \approx .928$
Alternative method:

$$
(0.8)^{1 / 3}=(1-0.2)^{1 / 3}=1-\frac{0.2}{3}+\frac{\frac{1}{3}\left(\frac{1}{3}-1\right)}{2!}(-0.2)^{2}+\frac{\frac{1}{3}\left(\frac{1}{3}-1\right)\left(\frac{1}{3}-2\right)}{3!}(-0.2)^{3}+\ldots
$$

Simplify onward by yourself.
Example 25 Evaluate $3 / 30$ correct to three places of decimal.
Solution $\sqrt{30}=(30)^{1 / 3}=(27+3)^{\frac{1}{3}}$

$$
\begin{aligned}
& =\left[27\left(1+\frac{3}{27}\right)\right]^{1 / 3}=(27)^{1 / 3}\left(1+\frac{1}{9}\right)^{1 / 3} \\
& =3\left(1+\frac{1}{9}\right)^{1 / 3}
\end{aligned}
$$

$$
\begin{aligned}
& =3\left[1+\frac{1}{3} \cdot \frac{1}{9}+\frac{\left(\frac{1}{3}\right)\left(-\frac{2}{3}\right)}{2!}\left(\frac{1}{9}\right)^{2}+\frac{\frac{1}{3}\left(-\frac{2}{3}\right)\left(-\frac{5}{3}\right)}{3!}\left(\frac{1}{9}\right)^{3}+\cdots\right] \\
& =3\left[1+\frac{1}{3} \cdot \frac{1}{9}-\frac{1}{9}\left(\frac{1}{9}\right)^{2}+\frac{5}{81}\left(\frac{1}{9}\right)^{3}+\cdots\right]=3\left[1+\frac{1}{27}-\left(\frac{1}{27}\right)^{2}+\cdots\right] \\
& \approx 3[1+0.03704-0.001372]=3[1.035668]=3.107004
\end{aligned}
$$

Thus $\sqrt[3]{30} \approx 3.107$

# 8.5.2 Finding the Remainder Using Binomial Theorem 

Example 26 Using binomial theorem, find the remainder when $5^{99}$ is divided by 13. Solution $5^{99}=5 \cdot 5^{98}=5 \cdot\left(5^{2}\right)^{49}=5 \cdot(25)^{49}$

$$
\begin{aligned}
& =5(26-1)^{49} \\
& =5\left[\binom{49}{0} 26^{48} 1^{0}-\binom{49}{1} 26^{48} 1^{1}+\binom{49}{2} 26^{47} 1^{2}+\ldots-\binom{49}{49} 26^{0} 1^{49}\right] \\
& =5\left[26^{49}-\binom{49}{1} 26^{48}+\binom{49}{2} 26^{47}+\ldots-1\right] \\
& =5 \cdot 26^{49}-5 \cdot\binom{49}{1} 26^{48}+5 \cdot\binom{49}{2} 26^{47}+\ldots-5 \\
& =\left[5 \cdot 26^{49}-5 \cdot\binom{49}{1} 26^{48}+5 \cdot\binom{49}{2} 26^{47}+\ldots-13\right]+8 \\
& =13 k+8, \text { where } k \text { is an integer }
\end{aligned}
$$

Hence, 8 is the remainder when $5^{99}$ is divided by 13.
Example 27 Using the binomial theorem, show that $11^{n}-10 n$ leaves a remainder 1 when divided by 100 for all positive integers $n$.

## Solution

$$
\begin{aligned}
& 11^{n}=(1+10)^{n}=\binom{n}{0} 1^{n} 10^{0}+\binom{n}{1} 1^{n-1} 10^{1}+\binom{n}{2} 1^{n-2} 10^{2}+\binom{n}{3} 1^{n-3} 10^{3}+\cdots+\binom{n}{n} 1^{0} 10^{n} \\
& 11^{n}=1+10 n+\binom{n}{2} 100+\binom{n}{3} 1000+\cdots+10^{n} \\
& 11^{n}-10 n=1+100\left[\binom{n}{2}+\binom{n}{3}(10)+\cdots+10^{n-2}\right]
\end{aligned}
$$

$11^{n}-10 n=1+100 \times$ an integer
$11^{n}-10 n=100 \times$ an integer +1
This show that $11^{n}-10 n$ leaves a remainder 1 when divided by 100 .

# 8.5.3 Finding Last Digit of a Number 

Example 28 Using binomial theorem, find the last two digits of the number $11^{12}$.
Solution $(11)^{12}=(10+1)^{12}$

$$
=\binom{12}{0} 10^{12} 1^{0}+\binom{12}{1} 10^{11} 1^{1}+\binom{12}{2} 10^{10} 1^{2}+\cdots+\binom{12}{11} 10^{1} 1^{11}+\binom{12}{12} 10^{0} 1^{12}
$$

The last two digits can be found by the last two terms, because the remaining terms are the multiples of 100 and hence do not affect the last two digits

$$
\binom{12}{11} 10^{1} 1^{11}+\binom{12}{12} 10^{0} 1^{12}=120+1=121
$$

The last two digits of 121 are 2,1 .
Hence the last two digits of $11^{12}$ are 2,1 .

## Divisibility Test

Example 29 Show that $(15)^{13}+(13)^{15}$ is divisible by 14 .
Solution $(15)^{13}+(13)^{15}=(14+1)^{13}+(14-1)^{15}$

$$
\begin{aligned}
&=\left[{ }^{13} C_{0}(14)^{13}+{ }^{13} C_{1}(14)^{12}+{ }^{13} C_{2}(14)^{11}+\cdots+{ }^{13} C_{13}\right] \\
&+\left[{ }^{15} C_{0}(14)^{15}-{ }^{15} C_{1}(14)^{14}+{ }^{15} C_{2}(14)^{13}-\cdots+{ }^{15} C_{14}(14)-{ }^{15} C_{15}\right] \\
&=\left[{ }^{13} C_{0}(14)^{13}+{ }^{13} C_{1}(14)^{12}+{ }^{13} C_{2}(14)^{11}+\cdots{ }^{13} C_{12}(14)+1\right. \\
&+{ }^{15} C_{0}(14)^{15}-{ }^{15} C_{1}(14)^{14}+\cdots+{ }^{15} C_{14}(14)-1] \\
&=14\left[{ }^{13} C_{0}(14)^{12}+{ }^{13} C_{1}(14)^{11}+{ }^{13} C_{2}(14)^{10}+\cdots+{ }^{13} C_{12}\right. \\
&+{ }^{15} C_{0}(14)^{14}-{ }^{15} C_{1}(14)^{13}+\cdots+{ }^{15} C_{14}]
\end{aligned}
$$

$=14 k$, where $k$ is an integer.
Thus, $14 k$ is divisible by 14 .

## Comparing Two Large Numbers

Example 30 Which number is larger $51^{25}$ or $49^{25}+50^{25}$ ?
Solution

$$
\begin{aligned}
51^{25} & =(50+1)^{25} \\
& =\binom{25}{0}(50)^{25}(1)^{0}+\binom{25}{1}(50)^{24}(1)^{1}+\binom{25}{2}(50)^{23}(1)^{2}+\binom{25}{3}(50)^{22}(1)^{2}+\cdots \\
& =(50)^{25}+25 \cdot(50)^{24}+\frac{25 \cdot 24}{1 \cdot 2}(50)^{23}+\frac{25 \cdot 24 \cdot 23}{1 \cdot 2 \cdot 3}(50)^{22}+\cdots
\end{aligned}
$$

Similarly

$$
49^{25}=(50-1)^{25}=(50)^{25}-25 \cdot(50)^{24}+\frac{25 \cdot 24}{1 \cdot 2}(50)^{25}-\frac{25 \cdot 24 \cdot 23}{1 \cdot 2 \cdot 3}(50)^{22}+\cdots
$$

By subtracting, we get

$$
\begin{aligned}
51^{25}-49^{25} & =2\left[25 \cdot(50)^{24}+\frac{25 \cdot 24 \cdot 23}{1 \cdot 2 \cdot 3} \cdot(50)^{22}+\cdots\right. \\
& =\left[(50)^{25}+2 \cdot \frac{25 \cdot 24 \cdot 23}{1 \cdot 2 \cdot 3} \cdot(50)^{22}+\cdots\right]>50^{25} \\
\Rightarrow(51)^{25}-(49)^{25} & >50^{25} \Rightarrow(51)^{25}>(49)^{25}+50^{25}
\end{aligned}
$$

Hence, $(51)^{25}$ is greater than $49^{25}+50^{25}$.
Economic Forecasting with Compound Interest
Example 31 A bank offers a compound interest rate of $5 \%$ per year. Sumaira invests Rs. 100,000 for 3 years. How much will her investment be worth at the end of 3 years? Solution Using the compound interest formula, the future value A of the investment is given by: $A=P\left(1+\frac{r}{n}\right)^{n}$
Where, $P=100,000$ (the principal), $r=0.05$ (the interest rate), $n=1$ (compounding once per year), $t=3$ (the time in years).
Substitute the values: $A=100000(1+0.05)^{1 \times 3}=1000(1.05)^{3}$
Using the binomial expansion for $(1.05)^{3}$ :

$$
\begin{aligned}
(1+0.05)^{3} & =1+3(0.05)+3(0.05)^{2}+(0.05)^{3} \\
& =1+0.15+0.0075+0.000125 \\
& =1.157625
\end{aligned}
$$

Now calculate the future value: $A=100000 \times 1.157625=115762.5$
So, after 3 years, the investment will be worth Rs. 115762.5.

# EXERCISE 8.4 

1. Using binomial theorem find the value of the following to three places of decimals:
(i) $\sqrt{99}$
(ii) $(1.03)^{\frac{1}{3}}$
(iii) $\frac{1}{1 / 252}$
(iv) $\frac{\sqrt{7}}{\sqrt{8}}$
2. Find the remainder when $8^{100}$ is divided by 7 .
3. Find the remainder when $2^{100}$ is divided by 3 .
4. Using the binomial theorem, find which number is larger:
(i) $19^{10}+20^{10}$ or $21^{10}$
(ii) $29^{15}+30^{15}$ or $31^{15}$

5. Using the binomial theorem, show that:
(i) $5^{7}+7^{5}$ is divisible by 36 .
(ii) $(17)^{15}+(13)^{7}$ is divisible by 6
(iii) $(21)^{9}+(19)^{11}$ is divisible by 20
(iv) $(31)^{4}+(29)^{6}$ is divisible by 30
(v) $(101)^{5}+(99)^{7}$ is divisible by 100
6. Using the binomial theorem, find the remainder when $3^{101}$ is divided by 8 .
7. Using the binomial theorem, find the last digit of the number (32) ${ }^{32}$.
8. Using the binomial theorem, show that $7^{n}-6 n$ leaves remainder 1 when divided by 6 for all positive integers $n$.
9. By using Binomial Theorem show that for each $n \in N, 5^{n}-1$ is divisible by 4.
10. By using Binomial Theorem show that for each $n \in N, 5^{n}-2^{n}$ is divisible by 3.
11. Show that $a^{2}+(a+2)^{2}+(a+4)^{2}+1$ is divisible by 12 , whenever " $a$ " is an odd integer.
12. A company expects its annual revenue to grow at a fixed rate of $6 \%$ per year. The revenue in year 1 is $\mathrm{R}=\mathrm{Rs} .10,000,000$. Estimate the company's revenue after 4 years using the binomial theorem for small growth rates.
13. A bank offers a compound interest rate of $10 \%$ per year. Zafar invests Rs. $2,000,000$ for 4 years. How much will his investment be worth at the end of 4 years?
14. Zaid is organizing a sports competition with 8 teams. Every team plays against every other team exactly once. How many matches will be played in total? Use Pascal's triangle to solve this.

# Division of Polynomials 

## INTRODUCTION

Polynomials play a fundamental role in algebra and have wide-ranging applications in various fields, including engineering, data science and digital communication. This unit explores polynomial division to determine the quotient and remainder. The remainder theorem is introduced as a powerful tool for evaluating polynomials efficiently, while the factor theorem is applied to factorize cubic polynomials. These concepts extend beyond theoretical mathematics, finding practical applications in polynomial regression, signal processing and coding theory. By mastering these techniques, students will develop a deeper understanding of polynomials and their significance in solving real-world problems.

### 9.1 Polynomial Function

A polynomial in $x$ is an expression of the form

$$
a_{n} x^{n}+a_{n-1} x^{n-1}+a_{n-2} x^{n-2}+\ldots+a_{2} x^{2}+a_{1} x+a_{0}
$$

where $n$ is a non-negative integer and the coefficients $a_{n}, a_{n-1}, a_{n-2}, \ldots, a_{1}$ and $a_{0}$ are real numbers. It can be considered as a polynomial function of $x$, the highest power of $x$ in a polynomial is called the degree of the polynomial. In the expression (i) if $a_{n} \neq 0$ then it is a polynomial of degree $n$. The polynomials $x^{2}-2 x+3$, $3 x^{3}+2 x^{2}-5 x+4$ are of degree 2 and 3 respectively.
Example 1 Divide the cubic polynomial $3 x^{3}-10 x^{2}+13 x-6$ by the linear polynomial $x-2$. Also find quotient and remainder.
Solution

$$
\begin{aligned}
& 3 x^{3}-4 x+5 \\
& \begin{array}{r}
x-2 \\
3 x^{3}-10 x^{2}+13 x-6 \\
3 x^{3}+6 x^{2}
\end{array} \\
& \begin{array}{r}
-4 x^{2}+13 x \\
+4 x^{2}+8 x
\end{array} \\
& \frac{5 x-6}{5 x+10}
\end{aligned}
$$

Hence, we can write: $3 x^{3}-10 x^{2}+13 x-6=(x-2)\left(3 x^{2}-4 x+5\right)+4$
So, quotient $-3 x^{2}-4 x+5$ and remainder $-4$.

Example 2 Divide the polynomial $x^{4}-3 x^{3}+5 x^{2}-7 x+2$ by $x^{2}-x+1$. Also find quotient and remainder.

# Soation 

$$
\begin{aligned}
& x^{3}-x+1 \begin{array}{c}
x^{3}-2 x+2 \\
x^{4}-3 x^{3}+5 x^{2}-7 x+2 \\
x^{4}+x^{3}+x^{2} \\
-2 x^{3}+4 x^{2}-7 x \\
\mp 2 x^{3}+2 x^{2} \mp 2 x \\
2 x^{2}-5 x+2 \\
-2 x^{2}+2 x+2 \\
-3 x
\end{array}
\end{aligned}
$$

So, quotient $=x^{2}-2 x+2$ and remainder $=-3 x$

### 9.1.1 Remainder Theorem

Statement: If a polynomial $f(x)$ of degree $n \geq 1$ is divided by $x-a$ till no $x$-term exists in the remainder, then $f(a)$ is the remainder.
Proof: Suppose we divide the polynomial $f(x)$ by $(x-a)$. Then there exists a unique quotient $q(x)$ and a unique remainder $R$ such that

$$
f(x)=(x-a) q(x)+R
$$

Substituting $x=a$ in equation (i), we get

$$
\begin{aligned}
& f(x)=(a-a) q(a)+R \\
& f(a)=R
\end{aligned}
$$

Hence remainder $=f(a)$
Example 3 Find the remainder without performing division when $f(x)=x^{4}+x^{3}+x^{2}+1$ is divided by $x+1$.
Solution Here $f(x)=x^{4}+x^{3}+x^{2}+1$ and $x-a=x+1 \Rightarrow a=-1$

$$
\begin{aligned}
\text { Remainder } & =f(-1) \\
& =(-1)^{4}+(-1)^{3}+(-1)^{2}+1 \\
& =1+(-1)+1+1=2
\end{aligned}
$$

(By remainder theorem)

Example 4 Find the value of $k$ if the polynomial $x^{3}+k x^{2}-7 x+6$ has a remainder -4 , when divided by $x+2$.
Solution Let $f(x)=x^{3}+k x^{2}-7 x+6$ and $x-a=x+2$, we have, $a=-2$
Remainder $=f(-2)$
(By remainder theorem)

$$
\begin{aligned}
& =(-2)^{3}+k(-2)^{2}-7(-2)+6 \\
& =-8+4 k+14+6 \\
& =4 k+12
\end{aligned}
$$

Given that remainder $=-4$

$$
\begin{aligned}
& 4 k+12=-4 \\
& \Rightarrow \quad 4 k=-16 \\
& \Rightarrow \quad k=-4
\end{aligned}
$$

# 9.1.2 Factor Theorem 

Statement: The polynomial $x-a$ is a factor of the polynomial $f(x)$ iff $f(a)=0$. In other words $x-a$ is a factor of $f(x)$ if and only if $x=a$ is the root of the polynomial equation $f(x)=0$.
Proof: Suppose $q(x)$ is the quotient and $R$ is the remainder when the polynomial $f(x)$ is divided by $x-a$, till no $x$-term exists in the remainder, then:

$$
f(x)=(x-a) q(x)+R
$$

Suppose $f(a)=0 \Rightarrow R=0$

$$
f(x)=(x-a) q(x)
$$

$(x-a)$ is a factor of $f(x)$
Conversely, if $(x-a)$ is a factor of $f(x)$, then $f(x)=(x-a) q(x)$ for some polynomial $q(x)$

$$
f(a)=0
$$

which proves the theorem.
Example 5 Show that $x-2$ is a factor of $f(x)=x^{3}-7 x+6$ without factorizing.
Solution Here, $f(x)=x^{3}-7 x+6$ and $a=2$

$$
\begin{aligned}
f(2) & =2^{3}-7(2)+6 \\
& =8-14+6=0
\end{aligned}
$$

(By factor theorem)
So, $x-2$ is a factor of $f(x)$.
Note To determine if a given linear polynomial $x-a$ is a factor of $f(x)$, we need to check whether $f(a)=0$.
Example 6 If $x+1$ and $x-2$ are factors of $x^{3}+p x^{2}+q x+2$. Find the values of $p$ and $q$.
Solution Let $f(x)=x^{3}+p x^{2}+q x+2$
Since, $x+1$ is a factor of $f(x)$.
So, $\quad f(-1)=0 \Rightarrow-1+p-q+2=0$

$$
p-q=-1
$$

Similarly, $x-2$ is also a factor of $f(x)$.
So, $\quad f(2)=0$

$$
\begin{aligned}
& 8+4 p+2 q+2=0 \\
& 4 p+2 q=-10 \\
& 2 p+q=-5
\end{aligned}
$$

By adding (i) and (ii), we have

$$
\begin{aligned}
& p=-2 \\
& \text { Put } \quad p=-2 \text { in (i), we have } \\
& q=p+1=-2+1=-1
\end{aligned}
$$

# 9.1.3 Synthetic Division 

There is a nice shortcut method for long division of a polynomial $f(x)$ by a polynomial of the form $x-a$. This process of division is called Synthetic Division.

To divide the polynomial $p x^{3}+q x^{3}+c x+d$ by $x-a$
[Image removed]

## Outline of the Method

(i) Write down the coefficients of the dividend $f(x)$ from left to right in decreasing order of powers of $x$. Insert 0 for any missing term.
(ii) To the left of the first line, write $a$ of the divisor $(x-a)$.
(iii) Use the following patterns to write the second and third lines:

Vertical pattern $(\downarrow) \quad$ Add terms
Diagonal pattern $(\nearrow)$ Multiply by $a$.
Example 7 If $(x-2)$ and $(x+2)$ are factors of $x^{4}-13 x^{2}+36$. Using synthetic division, find the other two factors.
Solution Let $f(x)=x^{8}-13 x^{3}+36$

$$
=x^{4}+0 x^{3}-13 x^{2}+0 x+36
$$

Here $x-a=x-2 \Rightarrow a=2$ and $x-a=x+2=x-(-2) \Rightarrow a=-2$
By synthetic Division:

$$
\begin{array}{c|cccc}
2 & 1 & 0 & -13 & 0 & 36 \\
& & 2 & 4 & -18 & -36 \\
\hline-2 & 1 & 2 & -9 & -18 & 0 \\
& & -2 & 0 & 18 & \\
\hline & 1 & 0 & -9 & 0 & \\
\hline
\end{array}
$$

$\therefore$ Quotient $=x^{2}+0 x-9=x^{3}-9=(x+3)(x-3)$
Therefore, other two factors are $(x+3)$ and $(x-3)$.

# EXERCISE 9.1 

1. Find remainder and quotient by simplifying the following:
(i) $\left(3 x^{2}-x+2\right) \div(x-1)$
(ii) $\left(x^{3}+12 x^{2}-3 x+4\right) \div(x-2)$
(iii) $\left(x^{4}-5 x^{3}-8 x^{2}+13 x+12\right) \div(x-6)$
(iv) $\left(5 x^{4}-3 x^{3}+2 x^{2}-1\right) \div\left(x^{2}+4\right)$
(v) $\left(3 x^{4}-5 x^{3}+4 x-6\right) \div\left(x^{2}-3 x+5\right)$
2. Use the remainder theorem to find the remainder when the first polynomial is divided by the second polynomial.
(i) $x^{2}+5 x+6, x-2$
(ii) $x^{3}+5 x^{2}+6, x+1$
(iii) $x^{4}+x^{3}+x^{2}+x+1, x-1$
(iv) $x^{4}+x^{3}+1, x+3$
(v) $x^{4}+x^{3}+2, x+2$
3. Use the factor theorem to determine if the first polynomial is a factor of the second polynomial.
(i) $x+1, x^{2}-1$
(ii) $x-2, x^{2}-5 x+6$
(iii) $x+1, x^{2}+x^{2}+x-3$
(iv) $x-2, x^{3}+x^{2}-7 x+2$
(v) $x-3, x^{4}-3 x^{3}+x^{2}-x+1$
4. Use synthetic division to show that $x$ is the zero of the polynomial and use the result to factorize the polynomial completely.
(i) $x^{3}-7 x+6, x=2$
(ii) $x^{3}-28 x-48, x=-4$
(iii) $2 x^{4}+7 x^{3}-4 x^{2}-27 x-18, x=2, x=-3$
5. Use synthetic division to find the quotient and the remainder when the polynomial $x^{4}-10 x^{2}-2 x+4$ is divided by $x+3$.
6. If $x+1$ and $x-2$ are factors of $x^{2}-p x^{2}+q x+2$. Using synthetic division, find the values of $p$ and $q$.
7. When the polynomial $4 x^{4}+2 x^{3}+k x^{3}+13$ is divided by $x+1$, the remainder is 16. Find the value of $k$.
8. When the polynomial $x^{3}+x^{2}+x+k$ is divided by $x+1$, the reminder is 7 . Find the value of $k$.

9. Use factor theorem to find the values of $p$ and $q$ if $x+1$ and $x-2$ are the factors of the polynomial $x^{3}+p x^{2}+q x+3$.
10. Use factor theorem to find the values of $a$ and $b$ if -2 and 2 are the roots of the polynomial $2 x^{3}+4 x^{2}+a x+b$.

# 9.2 Real Life Applications of Remainder and Factor Theorems 

In this article, we shall demonstrate how remainder and factor theorems are applied in different areas such as polynomial regression (used in statistical modeling), signal processing (used for filtering and error detection) and coding theory (used in data encryption and error correction in communication systems). These applications highlight the significance of polynomial analysis beyond theoretical mathematics.
Regression Analysis: It is a statistical method used to model the relationship between a dependent variable and one or more independent variables.
Polynomial Regression: It is a type of regression analysis where the relationship between the independent and dependent variables is modeled as an $n^{\text {th }}$-degree polynomial. It is used when the data shows a curved (non-linear) relationship, but we still want to fit a smooth, continuous function. Factor theorem is useful for reducing polynomial regression degree and remainder theorem helps in evaluating polynomials at given points.
Example 8 Consider a data set of monthly sales figures. A polynomial regression model $P(x)=x^{3}+x^{2}+2 x+1$ is fitted to this data. If the observed sales in the $3^{\text {rd }}$ month are 40 units, find the percentage error.

## Salation

$$
\begin{aligned}
\text { Error } & =\text { Observed }- \text { Predicted }=40-P(3) \\
\text { Now, } & \\
P(3) & =3^{3}+3^{2}+2(3)+1 \\
& =27+9+6+1 \\
& =43 \\
\text { Error } & =40-43 \\
& =-3 \\
\text { So, Percentage Error } & =\left|\frac{-3}{40}\right| \times 100 \\
& =7.5 \%
\end{aligned}
$$

Example 9 Suppose a polynomial regression model $P(x)=3 x^{3}-4 x^{2}+2 x-5$. If a data point at $x=-1$ is missing. What should be its predicted value?
Solution By remainder theorem

$$
\begin{aligned}
P(-1) & =3(-1)^{3}-4(-1)^{2}+2(-1)-5 \\
& =-3-4-2-5 \\
& =-14
\end{aligned}
$$

So, the predicted value of given polynomial regression model at $x=-1$ is -14 .
Digital Signal Processing (DSP): It is the used in computers or digital devices to analyze, change or improve signals like sound, images or sensor data. In the context of DSP, we often deal with systems represented by transfer functions in the z-domain, denoted as $\mathrm{H}(\mathrm{z})$. These transfer functions are rational functions, meaning they are ratios of two polynomials in $z$ i.e., $H(z)=\frac{B(z)}{A(z)}$, where $B(z)$ represents the numerator polynomial (related to the system's zeros) and $A(z)$ represents the denominator polynomial (related to the system's poles).
In signal processing, finding the roots of the numerator polynomial $B(z)$ provides the zeros of the system. If $B\left(z_{0}\right)=0$, then $\left(z-z_{0}\right)$ is a factor of $B(z)$. If $\left|z_{0}\right|=1$, this corresponds to a frequency that the system blocks.
Similarly, finding the roots of the denominator polynomial $A(z)$ provides the poles of the system. If $A\left(p_{0}\right)=0$, then $\left(z-p_{0}\right)$ is a factor of $A(z)$. The locations of these poles in the complex $z$-plane are crucial for determining the stability of the system. For a stable system, all poles must lie inside the unit circle $\left(\left|p_{0}\right|<1\right)$.
Example 10 A signal processing system has a transfer function with a denominator $A(z)=z^{2}-0.25$. Use factor theorem to find the poles of the system and determine if the system is stable.
Solution The poles occur when $A(z)=0$.

$$
\begin{aligned}
z^{2}-0.25 & =0 \\
z^{2}-(0.5)^{2} & =0 \\
(z-0.5)(z+0.5) & =0 \\
z-0.5 & =0 \text { or } z+0.5=0 \\
z & =0.5 \\
\text { or } z & =-0.5
\end{aligned}
$$

Thus, the system has poles at $z=0.5$ and $z=-0.5$. For stable system, all poles must lie inside the unit circle $(|z|<1)$. Here, $|0.5|=0.5<1$ and $|-0.5|=0.5<1$. Since both poles are inside the unit circle, the system is stable.

# EXERCISE 9.2 

1. Consider a data set at monthly sales figures. A polynomial regression model $P(x)=x^{3}+2 x^{2}+x-3$ is fitted to this data. If the observed sales in the $5^{\text {th }}$ month are 240 units, find the percentage error.
2. A retailer company has developed a polynomial regression model to predict weekly product demand: $D(w)=w^{3}-2 w^{2}+5 w-4$, where $D(w)$ represents predicted demand(in units) and $w$ is the week number. Use the remainder theorem to predict demand for $3^{\text {rd }}$ week. If the observe demand is 22 units, calculate the prediction error.
3. A digital signal processing system has a transfer function with a numerator $B(z)=z^{2}-z-2$. Use the factor theorem to find the zeros of the system.
4. A signal process system has a transfer function $H(z)=\frac{z^{2}+3 z+2}{z^{2}-0.2 z+0.9}$. Find the zero(s) of the transfer function by using factor theorem.
5. A signal process system has a transfer function $H(z)=\frac{z^{2}-0.5 z-0.5}{z^{3}+1}$. Find the zero(s) of the transfer function by using factor theorem.
6. A signal processing system has a transfer function with a denominator $A(z)=z^{2}-0.3 z-0.4$. Use factor theorem to find the poles of the system and determine if the system is stable.
7. The denominator of signal processing system's transfer function equal to $A(z)=z^{2}+1.2 z+0.35$ Use factor theorem to determine the location of the corresponding poles and assess the stability of the system.

# Trigonometric Identities 

## INTRODUCTION

In this unit, we shall first establish the fundamental law of trigonometry before discussing the Trigonometric Identities. For this we should know the formula to find the distance between two points in a plane.

### 10.1 Distance Formula: (Recall)

Let $P\left(x_{1}, y_{1}\right)$ and $Q\left(x_{2}, y_{2}\right)$ be two points. If " $d$ " denotes the distance between them,

$$
\begin{aligned}
& \text { then } \quad d=|\overline{P Q}|=\sqrt{\left(x_{1}-x_{2}\right)^{2}+\left(y_{1}-y_{2}\right)^{2}} \\
& \text { or } \quad=\sqrt{\left(x_{2}-x_{1}\right)^{2}+\left(y_{2}-y_{1}\right)^{2}}
\end{aligned}
$$

Example 1 Find distance between the following points:
(i) $A(3,8), B(5,6)$
(ii) $P(\cos x, \cos y), Q(\sin x, \sin y)$

## Solution

(i) Distance $=|\overline{A B}|=\sqrt{(3-5)^{2}+(8-6)^{2}}=\sqrt{4+4}=2 \sqrt{2}$
(ii) Distance $=|\overline{P Q}|=\sqrt{(\cos x-\sin x)^{2}+(\cos y-\sin y)^{2}}$

$$
\begin{aligned}
& =\sqrt{\cos ^{2} x+\sin ^{2} x-2 \cos x \sin x+\cos ^{2} y+\sin ^{2} y-2 \cos y \sin y} \\
& =\sqrt{2-2 \cos x \sin x-2 \cos y \sin y} \\
& =\sqrt{2-2(\cos x \sin x+\cos y \sin y)}
\end{aligned}
$$

### 10.1.1 Fundamental Law of Trigonometry

Let $\alpha$ and $\beta$ be any two angles (real numbers), then

$$
\cos (\alpha-\beta)=\cos \alpha \cos \beta+\sin \alpha \sin \beta
$$

which is called the Fundamental Law of Trigonometry.

Proof: For our convenience, let us assume that $\alpha>\beta>0$.
Consider a unit circle with centre at origin $O$.

Let terminal sides of angles $\alpha$ and $\beta$ cut the unit circle at $A$ and $B$ respectively. Evidently $m \angle A O B=\alpha-\beta$

Take a point $C$ on the unit circle such that $m \angle X O C=m \angle A O B=\alpha-\beta$.

Join $A, B$ and $C, D$.
Now angles $\alpha, \beta$ and $\alpha-\beta$ are in standard position.
$\therefore \quad$ The coordinates of $A$ are $(\cos \alpha, \sin \alpha)$.
The coordinates of $B$ are $(\cos \beta, \sin \beta)$
The coordinates of $C$ are $(\cos \alpha-\beta, \sin \alpha-\beta)$
and the coordinates of $D$ are $(1,0)$.
Now $\triangle A O B$ and $\triangle C O D$ are congruent.
Therefore,

$$
|A B|=|C D| \quad \Rightarrow \quad|A B|=|C D|
$$

Using the distance formula, we have:

$$
\begin{aligned}
& (\cos \alpha-\cos \beta)^{2}+(\sin \alpha-\sin \beta)^{2}=[(\cos (\alpha-\beta)-1]^{2}+[\sin (\alpha-\beta)-0]^{2} \\
& \Rightarrow \quad \cos ^{2} \alpha+\cos ^{2} \beta-2 \cos \alpha \cos \beta+\sin ^{2} \alpha+\sin ^{2} \beta-2 \sin \alpha \sin \beta \\
& =\cos ^{2}(\alpha-\beta)+1-2 \cos (\alpha-\beta)+\sin ^{2}(\alpha-\beta) \\
& \Rightarrow \quad 2-2(\cos \alpha \cos \beta+\sin \alpha \sin \beta)=2-2 \cos (\alpha-\beta) \\
& \text { Hence } \quad \cos (\alpha-\beta)=\cos \alpha \cos \beta+\sin \alpha \sin \beta .
\end{aligned}
$$

Note Although we have proved this law for $\alpha>\beta>0$, it is true for all values of $\alpha$ and $\beta$.
Suppose we know the values of $\sin$ and $\cos$ of two angles $\alpha$ and $\beta$, we can find $\cos (\alpha-\beta)$ using this law as explained in the following example:
Example 2 Find the value of $\sin \frac{5 \pi}{12}$.
Solution As $\frac{5 \pi}{12}=75^{\circ}=45^{\circ}+30^{\circ}=\frac{\pi}{4}+\frac{\pi}{6}$

$$
\begin{aligned}
\therefore \quad \sin \frac{5 \pi}{12} & =\sin \left(\frac{\pi}{4}+\frac{\pi}{6}\right)=\sin \frac{\pi}{4} \cos \frac{\pi}{6}+\cos \frac{\pi}{4} \sin \frac{\pi}{6} \\
& =\frac{1}{\sqrt{2}} \cdot \frac{\sqrt{3}}{2}+\frac{1}{\sqrt{2}} \cdot \frac{1}{2}=\frac{\sqrt{3}+1}{2 \sqrt{2}}
\end{aligned}
$$

# 10.1.2 Deductions from Fundamental Law 

1. We know that:

$$
\cos (\alpha-\beta)=\cos \alpha \cos \beta+\sin \alpha \sin \beta
$$

Putting $\alpha=\frac{\pi}{2}$ in it, we get

$$
\begin{aligned}
& \cos \left(\frac{\pi}{2}-\beta\right)=\cos \frac{\pi}{2} \cos \beta+\sin \frac{\pi}{2} \sin \beta \\
& \Rightarrow \quad \cos \left(\frac{\pi}{2}-\beta\right)=0 \cdot \cos \beta+1 \cdot \sin \beta \quad\left(\because \cos \frac{\pi}{2}=0, \sin \frac{\pi}{2}=1\right. \\
& \therefore \quad \cos \left(\frac{\pi}{2}-\beta\right)=\sin \beta
\end{aligned}
$$

2. We know that:

$$
\cos (\alpha-\beta)=\cos \alpha \cos \beta+\sin \alpha \sin \beta
$$

Putting $\beta=-\frac{\pi}{2}$ in it, we get

$$
\begin{aligned}
& \cos \left[\alpha-\left(-\frac{\pi}{2}\right)\right]=\cos \alpha \cdot \cos \left(-\frac{\pi}{2}\right)+\sin \alpha \sin \left(-\frac{\pi}{2}\right) \\
& \Rightarrow \quad \cos \left(\alpha+\frac{\pi}{2}\right)=\cos \alpha \cdot 0+\sin \alpha(-1) \\
& \therefore \quad \cos \left(\frac{\pi}{2}+\alpha\right)=-\sin \alpha
\end{aligned}
$$

$$
\begin{aligned}
& \text { (ii) }
\end{aligned}
$$

3. We know that:

$$
\cos \left(\frac{\pi}{2}-\beta\right)=\sin \beta
$$

[(i) above]

Putting $\beta=\frac{\pi}{2}+\alpha$ in it, we get

$$
\cos \left[\frac{\pi}{2}-\left(\frac{\pi}{2}+\alpha\right)\right]=\sin \left(\frac{\pi}{2}+\alpha\right)
$$

$$
\begin{aligned}
& \Rightarrow \quad \cos (-\alpha)=\sin \left(\frac{\pi}{2}+\alpha\right) \\
& \Rightarrow \quad \cos \alpha=\sin \left(\frac{\pi}{2}+\alpha\right) \quad[\because \cos (-\alpha)=\cos \alpha] \\
& \sin \left(\frac{\pi}{2}+\alpha\right)=\cos \alpha
\end{aligned}
$$

4. We know that:

$$
\cos (\alpha-\beta)=\cos \alpha \cos \beta+\sin \alpha \sin \beta
$$

Replacing $\beta$ by $-\beta$ we get

$$
\begin{aligned}
& \cos [\alpha-(-\beta)]=\cos \alpha \cos (-\beta)+\sin \alpha \sin (-\beta) \\
& {[\because \cos (-\beta)=\cos \beta, \sin (-\beta)=-\sin \beta]} \\
& \Rightarrow \quad \cos (\alpha+\beta)=\cos \alpha \cos \beta-\sin \alpha \sin \beta
\end{aligned}
$$

5. We know that:

$$
\cos (\alpha+\beta)=\cos \alpha \cos \beta-\sin \alpha \sin \beta
$$

Replacing $\alpha$ by $\frac{\pi}{2}+\alpha$, we get

$$
\begin{aligned}
& \cos \left[\left(\frac{\pi}{2}+\alpha\right)+\beta\right]=\cos \left(\frac{\pi}{2}+\alpha\right) \cos \beta-\sin \left(\frac{\pi}{2}+\alpha\right) \sin \beta \\
& \Rightarrow \quad \cos \left[\frac{\pi}{2}+(\alpha+\beta)\right]=-\sin \alpha \cos \beta-\cos \alpha \sin \beta \\
& \Rightarrow \quad \sin (\alpha+\beta)=-[\sin \alpha \cos \beta+\cos \alpha \sin \beta] \\
& \therefore \quad \sin (\alpha+\beta)=\sin \alpha \cos \beta+\cos \alpha \sin \beta
\end{aligned}
$$

6. We know that:

$$
\sin (\alpha+\beta)=\sin \alpha \cos \beta+\cos \alpha \sin \beta \quad \text { [from (v) above] }
$$

Replacing $\beta$ by $-\beta$, we get

$$
\begin{aligned}
& \sin (\alpha-\beta)=\sin \alpha \cos (-\beta)+\cos \alpha \sin (-\beta) \quad \begin{cases}\because & \sin (-\beta)=-\sin \beta \\
& \cos (-\beta)=\cos \beta
\end{cases} \\
& \therefore \quad \sin (\alpha-\beta)=\sin \alpha \cos \beta-\cos \alpha \sin \beta
\end{aligned}
$$

7. We know that:

$$
\cos (\alpha-\beta)=\cos \alpha \cos \beta+\sin \alpha \cdot \sin \beta
$$

Let $\alpha=2 \pi$ and $\beta=\theta$

$$
\begin{aligned}
\therefore \quad \cos (2 \pi-\theta) & =\cos 2 \pi \cdot \cos \theta+\sin 2 \pi \sin \theta \\
& =1 \cdot \cos \theta+0 \cdot \sin \theta \\
& =\cos \theta
\end{aligned}
$$

8. We know that:

$$
\begin{aligned}
\sin (\alpha-\beta) & =\sin \alpha \cdot \cos \beta-\cos \alpha \cdot \sin \beta \\
\sin (2 \pi-\theta) & =\sin 2 \pi \cdot \cos \theta-\cos 2 \pi \sin \theta \\
& =0 \cdot \cos \theta-1 \cdot \sin \theta \\
& =-\sin \theta
\end{aligned}
$$

$$
\begin{aligned}
& =-\sin \theta \\
& \text { (viii) }
\end{aligned}
$$

9. $\quad \tan (\alpha+\beta)=\frac{\sin (\alpha+\beta)}{\cos (\alpha+\beta)}=\frac{\sin \alpha \cos \beta-\cos \alpha \sin \beta}{\cos \alpha \cos \beta-\sin \alpha \sin \beta}$

$$
=\frac{\frac{\sin \alpha \cos \beta}{\cos \alpha \cos \beta}+\frac{\cos \alpha \sin \beta}{\cos \alpha \cos \beta}}{\frac{\cos \alpha \cos \beta}{\cos \alpha \cos \beta}-\frac{\sin \alpha \sin \beta}{\cos \alpha \cos \beta}} \quad \begin{aligned}
& \text { Dividing } \\
& \text { numerator and } \\
& \text { denominator by } \\
& \cos \alpha \cos \beta
\end{aligned}
$$

$$
\tan (\alpha+\beta)=\frac{\tan \alpha+\tan \beta}{1-\tan \alpha \tan \beta}
$$

10. $\quad \tan (\alpha-\beta)=\frac{\sin (\alpha-\beta)}{\cos (\alpha-\beta)}=\frac{\sin \alpha \cos \beta-\cos \alpha \sin \beta}{\cos \alpha \cos \beta+\sin \alpha \sin \beta}$

$$
=\frac{\frac{\sin \alpha \cos \beta}{\cos \alpha \cos \beta}-\frac{\cos \alpha \sin \beta}{\cos \alpha \cos \beta}}{\frac{\cos \alpha \cos \beta}{\cos \alpha \cos \beta}+\frac{\sin \alpha \sin \beta}{\cos \alpha \cos \beta}} \quad \begin{aligned}
& \text { Dividing } \\
& \text { numerator and } \\
& \text { denominator by } \\
& \cos \alpha \cos \beta
\end{aligned}
$$

$$
\tan (\alpha-\beta)=\frac{\tan \alpha-\tan \beta}{1+\tan \alpha \tan \beta}
$$

# 10.2 Trigonometric Ratios of Allied Angles 

Two angles $\alpha$ and $\beta$ are said to be allied, if $\alpha \pm \beta=n\left(90^{\circ}\right), n \in z$
For example, $\pm \alpha, 90^{\circ} \pm \alpha, 180^{\circ} \pm \alpha, 270^{\circ} \pm \alpha$ and $360^{\circ} \pm \alpha$ are some allied angles of $\alpha$. Using fundamental law of trigonometry, $\cos (\alpha-\beta)=\cos \alpha \cos \beta+\sin \alpha \sin \beta$ and its deductions, we derive the following identities:

$$
\begin{aligned}
& \sin \left(\frac{\pi}{2}-\theta\right)=\cos \theta, \cos \left(\frac{\pi}{2}-\theta\right)=\sin \theta, \tan \left(\frac{\pi}{2}-\theta\right)=\cot \theta \\
& \sin \left(\frac{\pi}{2}+\theta\right)=\cos \theta, \cos \left(\frac{\pi}{2}+\theta\right)=-\sin \theta, \tan \left(\frac{\pi}{2}+\theta\right)=-\cot \theta \\
& \left\{\begin{array}{l}
\sin (\pi-\theta)=\sin \theta, \cos (\pi-\theta)=-\cos \theta, \tan (\pi-\theta)=-\tan \theta \\
\sin (\pi+\theta)=-\sin \theta, \cos (\pi+\theta)=-\cos \theta, \tan (\pi+\theta)=\tan \theta
\end{array}\right. \\
& \sin \left(\frac{3 \pi}{2}-\theta\right)=-\cos \theta, \cos \left(\frac{3 \pi}{2}-\theta\right)=-\sin \theta, \tan \left(\frac{3 \pi}{2}-\theta\right)=\cot \theta \\
& \sin \left(\frac{3 \pi}{2}+\theta\right)=-\cos \theta, \cos \left(\frac{3 \pi}{2}+\theta\right)=\sin \theta, \tan \left(\frac{3 \pi}{2}+\theta\right)=-\cot \theta \\
& \sin (2 \pi-\theta)=-\sin \theta, \cos (2 \pi-\theta)=\cos \theta, \tan (2 \pi-\theta)=-\tan \theta \\
& \sin (2 \pi+\theta)=\sin \theta, \cos (2 \pi+\theta)=\cos \theta, \tan (2 \pi+\theta)=\tan \theta
\end{aligned}
$$

The above results also apply to the reciprocals of sine, cosine and tangent. These results are to be applied frequently in the study of trigonometry and they can be remembered by using the following device:

1. If $\theta$ is added to or subtracted from odd multiple of right angle, the trigonometric ratios change into co-ratios and vice versa.
i.e., $\sin \quad \Longleftrightarrow \cos , \tan \Longleftrightarrow \cot , \sec \Longleftrightarrow \operatorname{cosec}$
e.g.

$$
\sin \left(\frac{\pi}{2}-\theta\right)=\cos \theta \quad \text { and } \quad \cos \left(\frac{3 \pi}{2}+\theta\right)=\sin \theta
$$

2. If $\theta$ is added to or subtracted from an even multiple of $\frac{\pi}{2}$, the trigonometric ratios shall remain the same.
3. So far as the sign of the results is concerned, it is determined by the quadrant in which the terminal arm of the angle lies.
e.g. $\sin (\pi-\theta)=\sin \theta, \quad \tan (\pi+\theta)=\tan \theta, \quad \cos (2 \pi-\theta)=\cos \theta$.

| Measure of the angle | Quad. |
| :--: | :--: |
| $\frac{\pi}{2}-\theta$ | I |
| $\frac{\pi}{2}+\theta$ or $\pi-\theta$ | II |
| $\pi+\theta$ or $\frac{3 \pi}{2}-\theta$ | III |
| $\frac{3 \pi}{2}+\theta$ or $2 \pi-\theta$ | IV |

(a) $\quad \ln \sin \left(\frac{\pi}{2}-\theta\right), \sin \left(\frac{\pi}{2}+\theta\right), \sin \left(\frac{3 \pi}{2}-\theta\right)$ and $\sin \left(\frac{3 \pi}{2}+\theta\right)$ odd multiplies of $\frac{\pi}{2}$ are involved.

Therefore, sin will change into cos.
Moreover, the angle of measure
(i) $\left(\frac{\pi}{2}-\theta\right)$ will have terminal side in Quad. I,

$$
\text { So, } \sin \left(\frac{\pi}{2}-\theta\right)=\cos \theta
$$

(ii) $\left(\frac{\pi}{2}+\theta\right)$ will have terminal side in Quad. II,

$$
\text { So, } \sin \left(\frac{\pi}{2}+\theta\right)=\cos \theta
$$

(iii) $\left(\frac{3 \pi}{2}-\theta\right)$ will have terminal side in Quad. III,

$$
\text { So, } \sin \left(\frac{3 \pi}{2}-\theta\right)=-\cos \theta
$$

(iv) $\left(\frac{3 \pi}{2}+\theta\right)$ will have terminal side in Quad. IV,

$$
\text { So, } \sin \left(\frac{3 \pi}{2}+\theta\right)=-\cos \theta
$$

(b) In $\cos (\pi-\theta), \cos (\pi+\theta), \cos (2 \pi-\theta)$ and $\cos (2 \pi+\theta)$, even multiples of $\frac{\pi}{2}$ are involved.

Therefore, cos will remain as cos.
Moreover, the angle of measure
(i) $(\pi-\theta)$ will have terminal side in Quad. II, therefore

$$
\cos (\pi-\theta)=-\cos \theta
$$

(ii) $(\pi+\theta)$ will have terminal side in Quad. III, so

$$
\cos (\pi+\theta)=-\cos \theta
$$

(iii) $(2 \pi-\theta)$ will have terminal side in Quad. IV, so

$$
\cos (2 \pi-\theta)=\cos \theta
$$

(iv) $(2 \pi+\theta)$ will have terminal side in Quad. I, so

$$
\cos (2 \pi+\theta)=\cos \theta
$$

Example 3 Without using the tables, write down the values of:
(i) $\sin 225^{\circ}$
(ii) $\tan 600^{\circ}$
(iii) $\cot \left(-225^{\circ}\right)$
(iv) $\operatorname{cosec}\left(-420^{\circ}\right)$

Solution (i) $\sin 225^{\circ}=\sin (180+45)^{\circ}=-\sin 45^{\circ}=-\frac{1}{\sqrt{2}}$
(ii) $\tan 600^{\circ}=\tan (540+60)^{\circ}=\tan (6 \times 90+60)^{\circ}=\tan 60^{\circ}=\sqrt{3}$
(iii) $\cot \left(-225^{\circ}\right)=-\cot 225^{\circ}=-\cot (180+45)^{\circ}=-\cot (2 \times 90+45)^{\circ}=-\left(\cot 45^{\circ}\right)=1$
(iv) $\operatorname{cosec}\left(-420^{\circ}\right)=-\operatorname{cosec} 420^{\circ}=-\operatorname{cosec}(360+60)^{\circ}=-\operatorname{cosec}(4 \times 90+60)^{\circ}$

$$
=-\operatorname{cosec} 60^{\circ}=\frac{-2}{\sqrt{3}}
$$

Example 4 Simplify: $\frac{\sin \left(180^{\circ}-\theta\right) \cos \left(360^{\circ}-\theta\right) \tan \left(90^{\circ}+\theta\right)}{\sin \left(90^{\circ}-\theta\right) \cos \left(180^{\circ}+\theta\right) \tan \left(270^{\circ}-\theta\right)}$

$$
\text { Solution Because }\left\{\begin{array}{l}
\sin \left(180^{\circ}-\theta\right)=\sin \theta, \cos \left(360^{\circ}-\theta\right)=\cos \theta \\
\tan \left(90^{\circ}+\theta\right)=-\cot \theta, \sin \left(90^{\circ}-\theta\right)=\cos \theta \\
\cos \left(180^{\circ}+\theta\right)=-\cos \theta, \tan \left(270^{\circ}-\theta\right)=\cot \theta
\end{array}\right.
$$

Therefore, $\frac{\sin \theta \cdot \cos \theta \cdot(-\cot \theta)}{\cos \theta \cdot(-\cos \theta) \cdot \cot \theta}=\frac{-\sin \theta}{-\cos \theta}=\tan \theta$

# EXERCISE 10.1 

1. Without using the tables, find the values of:
(i) $\cos \left(-1230^{\circ}\right)$
(ii) $\tan \left(-1035^{\circ}\right)$
(iii) $\sec \left(1140^{\circ}\right)$
(iv) $\operatorname{cosec}\left(-690^{\circ}\right)$
(v) $\cot \left(1320^{\circ}\right)$
(vi) $\cos \left(-240^{\circ}\right)$
2. Express each of the following as a trigonometric function of an angle of positive degree measure of less than $45^{\circ}$.
(i) $\cos 168^{\circ}$
(ii) $\sin 192^{\circ}$
(iii) $\cos 333^{\circ}$
(iv) $\tan 213^{\circ}$
(v) $\cos \left(-435^{\circ}\right)$
(vi) $\sin 219^{\circ}$
(vii) $\tan \left(-597^{\circ}\right)$
(viii) $\cos \left(-111^{\circ}\right)$
(ix) $\sin \left(-390^{\circ}\right)$
3. Prove the following:
(i) $\sin \left(180^{\circ}+\alpha\right) \sin \left(90^{\circ}-\alpha\right)=-\sin \alpha \cos \alpha$
(ii) $\sin 810^{\circ} \sin 630^{\circ}+\cos 135^{\circ} \sin 225^{\circ}=\frac{1}{2}$
(iii) $\tan 150^{\circ} \cot 330^{\circ}-2 \sec 135^{\circ} \operatorname{cosec} 225^{\circ}=-3$
(iv) $\sin 210^{\circ}+\cos 240^{\circ}+\tan 225^{\circ}+\cot 225^{\circ}=1$
4. Prove that:
(i) $\frac{\tan \left(180^{\circ}+\alpha\right) \cot \left(90^{\circ}-\alpha\right)}{\sin \left(360^{\circ}-\alpha\right) \cos \left(270^{\circ}+\alpha\right)}=-\sec ^{2} \alpha$
(ii) $\frac{\sin ^{2}(\pi+\theta) \tan \left(\frac{3 \pi}{2}+\theta\right)}{\cot ^{2}\left(\frac{3 \pi}{2}-\theta\right) \cos ^{2}(\pi-\theta) \operatorname{cosec}(2 \pi-\theta)}=\cos \theta$
(iii) $\frac{\cos \left(90^{\circ}+\theta\right) \sec (-\theta) \tan \left(180^{\circ}-\theta\right)}{\sec \left(360^{\circ}-\theta\right) \sin \left(180^{\circ}+\theta\right) \cot \left(90^{\circ}-\theta\right)}=-1$
5. Show that: $\sec \left(\frac{3 \pi}{2}-\theta\right) \sec \left(\frac{5 \pi}{2}-\theta\right)-\tan \left(\frac{3 \pi}{2}-\theta\right) \tan \left(\frac{5 \pi}{2}+\theta\right)=-1$
6. If $\alpha, \beta, \gamma$ are the angles of a triangle $A B C$, then prove that
(i) $\sin (\alpha+\beta)=\sin \gamma$
(ii) $\sec \left(\frac{\alpha+\beta}{2}\right)=\csc \frac{\gamma}{2}$
(iii) $\operatorname{cosec} \alpha=\frac{1}{\sin (\beta+\gamma)}$
(iv) $\tan (\alpha+\beta)+\tan \gamma=0$.

# 10.3 Further Applications of Basic Identities 

Example 5
Prove that: $\sin (\alpha+\beta) \sin (\alpha-\beta)=\sin ^{2} \alpha-\sin ^{2} \beta$

$$
=\cos ^{2} \beta-\cos ^{2} \alpha
$$

Solution L.H.S. $=\sin (\alpha+\beta) \sin (\alpha-\beta)$

$$
\begin{aligned}
& =(\sin \alpha \cos \beta+\cos \alpha \sin \beta)(\sin \alpha \cos \beta-\cos \alpha \sin \beta) \\
& =\sin ^{2} \alpha \cos ^{2} \beta-\cos ^{2} \alpha \sin ^{2} \beta \\
& =\sin ^{2} \alpha\left(1-\sin ^{2} \beta\right)-\left(1-\sin ^{2} \alpha\right) \sin ^{2} \beta \\
& =\sin ^{2} \alpha-\sin ^{2} \alpha \sin ^{2} \beta-\sin ^{2} \beta+\sin ^{2} \alpha \sin ^{2} \beta \\
& =\sin ^{2} \alpha-\sin ^{2} \beta \\
& =\left(1-\cos ^{2} \alpha\right)-\left(1-\cos ^{2} \beta\right) \\
& =1-\cos ^{2} \alpha-1+\cos ^{2} \beta \\
& =\cos ^{2} \beta-\cos ^{2} \alpha
\end{aligned}
$$

Example 6 Without using tables, find the values of all trigonometric functions of $105^{\circ}$
Solution As $105^{\circ}=60^{\circ}+45^{\circ}$

$$
\begin{aligned}
\sin 105^{\circ} & =\sin \left(60^{\circ}+45^{\circ}\right)=\sin 60^{\circ} \cos 45^{\circ}+\cos 60^{\circ} \sin 45^{\circ} \\
& =\left(\frac{\sqrt{3}}{2}\right)\left(\frac{1}{\sqrt{2}}\right)+\left(\frac{1}{2}\right)\left(\frac{1}{\sqrt{2}}\right)=\frac{\sqrt{3}+1}{2 \sqrt{2}} \\
\cos 105^{\circ} & =\cos \left(60^{\circ}+45^{\circ}\right)=\cos 60^{\circ} \cos 45^{\circ}-\sin 60^{\circ} \sin 45^{\circ} \\
& =\left(\frac{1}{2}\right)\left(\frac{1}{\sqrt{2}}\right)-\left(\frac{\sqrt{3}}{2}\right)\left(\frac{1}{\sqrt{2}}\right)-=\frac{1-\sqrt{3}}{2 \sqrt{2}} \\
\tan 105^{\circ} & =\tan \left(60^{\circ}+45^{\circ}\right)=\frac{\tan 60^{\circ}+\tan 45^{\circ}}{1-\tan 60^{\circ} \tan 45^{\circ}} \\
& =\frac{\sqrt{3}+1}{1-\sqrt{3} \cdot 1}=\frac{1+\sqrt{3}}{1-\sqrt{3}} \\
\cot 105^{\circ} & =\frac{1}{\tan 105^{\circ}}=\frac{1-\sqrt{3}}{1+\sqrt{3}} \\
\operatorname{cosec} 105^{\circ} & =\frac{1}{\sin 105^{\circ}}=\frac{2 \sqrt{2}}{\sqrt{3}+1} \\
\text { and } \quad \sec 105^{\circ} & =\frac{1}{\cos 105^{\circ}}=\frac{2 \sqrt{2}}{1-\sqrt{3}}
\end{aligned}
$$

Example 7 Prove that: $\frac{\cos 11^{\circ}+\sin 11^{\circ}}{\cos 11^{\circ}-\sin 11^{\circ}}=\tan 56^{\circ}$
Solution Consider

$$
\begin{aligned}
& \text { R.H.S }=\tan 56^{\circ}=\tan \left(45^{\circ}+11^{\circ}\right)=\frac{\tan 45^{\circ}+\tan 11^{\circ}}{1-\tan 45^{\circ} \tan 11^{\circ}} \\
& =\frac{1+\tan 11^{\circ}}{1-\tan 11^{\circ}}=\frac{1+\frac{\sin 11^{\circ}}{\cos 11^{\circ}}}{1-\frac{\sin 11^{\circ}}{\cos 11^{\circ}}}=\frac{\cos 11^{\circ}+\sin 11^{\circ}}{\cos 11^{\circ}-\sin 11^{\circ}}=\text { L.H.S }
\end{aligned}
$$

Hence $\frac{\cos 11^{\circ}+\sin 11^{\circ}}{\cos 11^{\circ}-\sin 11^{\circ}}=\tan 56^{\circ}$
Example 8 If $\cos \alpha=-\frac{7}{25}, \tan \beta=\frac{12}{5}$, the terminal side of the angle of measure $\alpha$ is in the II quadrant and that of $\beta$ is in the III quadrant, find the values of:
(i) $\sin (\alpha+\beta)$
(ii) $\cos (\alpha+\beta)$

In which quadrant does the terminal side of the angle of measure $(\alpha+\beta)$ lie?
Solution We know that $\sin ^{2} \alpha+\cos ^{2} \alpha=1$
Therefore, $\sin \alpha= \pm \sqrt{1-\cos ^{2} \alpha}= \pm \sqrt{1-\left(-\frac{7}{25}\right)^{2}}= \pm \sqrt{\frac{576}{625}}= \pm \frac{24}{25}$
As the terminal side of the angle of measure of $\alpha$ is in the II quadrant, where $\sin \alpha$ is positive.

So, $\quad \sin \alpha=\frac{24}{25}$
Now $\sec \beta= \pm \sqrt{1+\tan ^{2} \beta}= \pm \sqrt{1+\left(\frac{12}{5}\right)^{2}}= \pm \frac{13}{5}$
As the terminal side of the angle of measure of $\beta$ in the quadrant III, so sec $\beta$ is negative

$$
\begin{aligned}
& \sec \beta=-\frac{13}{5} \quad \text { and } \quad \cos \beta=-\frac{5}{13} \\
& \sin \beta= \pm \sqrt{1-\cos ^{2} \beta}= \pm \sqrt{1-\left(-\frac{5}{13}\right)^{2}}= \pm \sqrt{\frac{144}{169}}= \pm \frac{12}{13}
\end{aligned}
$$

As the terminal arm of the angle of measure $\beta$ is in the III quadrant, so $\sin \beta$ is negative

$$
\sin \beta=-\frac{12}{13}
$$

$\sin (\alpha+\beta)=\sin \alpha \cos \beta+\cos \alpha \sin \beta$

$$
=\left(\frac{24}{25}\right)\left(-\frac{5}{13}\right)+\left(-\frac{7}{25}\right)\left(-\frac{12}{13}\right)=\frac{-120+84}{325}=-\frac{36}{325}
$$

and $\cos (\alpha+\beta)=\cos \alpha \cos \beta-\sin \alpha \sin \beta$

$$
=\left(-\frac{7}{25}\right)\left(-\frac{5}{13}\right)-\left(\frac{24}{25}\right)\left(-\frac{12}{13}\right)=\frac{35+288}{325}=\frac{323}{325}
$$

As, $\sin (\alpha+\beta)$ is -ve and $\cos (\alpha+\beta)$ is +ve
Thus, the terminal arm of the angle of measure $(\alpha+\beta)$ is in the quadrant IV.
Example 9 If $\alpha, \beta, \gamma$ are the angles of $\triangle A B C$, prove that:
(i) $\tan \alpha+\tan \beta+\tan \gamma=\tan \alpha \tan \beta \tan \gamma$
(ii) $\tan \frac{\alpha}{2} \tan \frac{\beta}{2}+\tan \frac{\beta}{2} \tan \frac{\gamma}{2}+\tan \frac{\gamma}{2} \tan \frac{\alpha}{2}=1$

Solution As $\alpha, \beta, \gamma$ are the angles of $\triangle A B C$, therefore

$$
\begin{aligned}
\alpha+\beta+\gamma & =180^{\circ} \\
\alpha+\beta & =180^{\circ}-\gamma
\end{aligned}
$$

(i) $\tan (\alpha+\beta)=\tan \left(180^{\circ}-\gamma\right)$

$$
\begin{aligned}
& \frac{\tan \alpha+\tan \beta}{1-\tan \alpha \tan \beta}=-\tan \gamma \\
& \tan \alpha+\tan \beta=-\tan \gamma+\tan \alpha \tan \beta \tan \gamma
\end{aligned}
$$

$\tan \alpha+\tan \beta+\tan \gamma=\tan \alpha \tan \beta \tan \gamma$
(ii) As $\alpha+\beta+\gamma=180^{\circ} \Rightarrow \frac{\alpha}{2}+\frac{\beta}{2}+\frac{\gamma}{2}=90^{\circ}$

$$
\begin{aligned}
& \text { so } \quad \frac{\alpha}{2}+\frac{\beta}{2}=90^{\circ}-\frac{\gamma}{2} \\
& \tan \left(\frac{\alpha}{2}+\frac{\beta}{2}\right)=\tan \left(90^{\circ}-\frac{\gamma}{2}\right) \\
& \frac{\tan \frac{\alpha}{2}+\tan \frac{\beta}{2}}{1-\tan \frac{\alpha}{2} \tan \frac{\beta}{2}}=\cot \frac{\gamma}{2}=\frac{1}{\tan \frac{\gamma}{2}} \\
& \tan \frac{\alpha}{2} \tan \frac{\gamma}{2}+\tan \frac{\beta}{2} \tan \frac{\gamma}{2}=1-\tan \frac{\alpha}{2} \tan \frac{\beta}{2} \\
& \tan \frac{\alpha}{2} \tan \frac{\beta}{2}+\tan \frac{\beta}{2} \tan \frac{\gamma}{2}+\tan \frac{\gamma}{2} \tan \frac{\alpha}{2}=1
\end{aligned}
$$

Example16 Express $3 \sin \theta+4 \cos \theta$ in the form $r \sin (\theta+\phi)$, where the terminal side of the angle of measure $\phi$ is in quadrant 1 .

| Solution | Let $3=r \cos \phi$ | (i) |
| :-- | :-- | :-- |
|  | and $4=r \sin \phi$ | (ii) |

Squaring then adding (i) and (ii)

$$
3^{2}+4^{2}=r^{2} \cos ^{2} \phi+r^{2} \sin ^{2} \phi
$$

Dividing (ii) by (i)

$$
\begin{aligned}
& \Rightarrow \quad 9+16=r^{2}\left(\cos ^{2} \phi+\sin ^{2} \phi\right)\left\{\begin{array}{l}
\frac{4}{3}=\frac{r \sin \phi}{r \cos \phi} \\
\frac{4}{3}=\tan \phi \\
\frac{4}{3}=\tan \phi \\
\tan \phi=\frac{4}{3}
\end{array}\right. \\
& 3 \sin \theta+4 \cos \theta=r \cos \phi \sin \theta+r \sin \phi \cos \theta \\
& =r(\sin \theta \cos \phi+\cos \theta \sin \phi) \\
& =r \sin (\theta+\phi) \\
& \text { where } \quad r=5 \quad \text { and } \quad \tan ^{-1} \phi=\frac{4}{3}
\end{aligned}
$$

# EXERCISE 10.2 

1. Without using table find the values of the following:
(i) $\sin 15^{\circ}$
(ii) $\cos 15^{\circ}$
(iii) $\tan 15^{\circ}$
(iv) $\sin 105^{\circ}$
(v) $\cos 105^{\circ}$
(vi) $\tan 105^{\circ}$
2. Prove that
(i) $\sin \left(45^{\circ}+\alpha\right)=\frac{1}{\sqrt{2}}(\sin \alpha+\cos \alpha)$
(ii) $\cos \left(\alpha+45^{\circ}\right)=\frac{1}{\sqrt{2}}(\cos \alpha-\sin \alpha)$
3. Prove that:
(i) $\tan \left(45^{\circ}+A\right) \tan \left(45^{\circ}-A\right)=1$
(ii) $\tan \left(\frac{\pi}{4}-\theta\right)+\tan \left(\frac{3 \pi}{4}+\theta\right)=0$
(iii) $\quad \sin \left(\theta+\frac{\pi}{6}\right)+\cos \left(\theta+\frac{\pi}{3}\right)=\cos \theta$
(iv) $\frac{\sin \theta-\cos \theta \tan \frac{\theta}{2}}{\cos \theta+\sin \theta \tan \frac{\theta}{2}}=\tan \frac{\theta}{2}$
(v) $\frac{1-\tan \theta \tan \phi}{1+\tan \theta \tan \phi}=\frac{\cos (\theta+\phi)}{\cos (\theta-\phi)}$

4. Show that: $\cos (\alpha+\beta) \cos (\alpha-\beta)=\cos ^{2} \alpha-\sin ^{2} \beta=\cos ^{2} \beta-\sin ^{2} \alpha$
5. Show that: $\frac{\sin (\alpha+\beta)+\sin (\alpha-\beta)}{\cos (\alpha+\beta)+\cos (\alpha-\beta)}=\tan \alpha$
6. Show that: (i) $\sin ^{2}\left(\alpha+\frac{\beta}{2}\right)-\sin ^{2}\left(\alpha-\frac{\beta}{2}\right)=\sin 2 \alpha \cdot \sin \beta$
(ii) $\sin ^{2} \alpha+\sin ^{2} \beta+\cos ^{2}(\alpha+\beta)+2 \sin \alpha \cdot \sin \beta \cdot \cos (\alpha+\beta)=1$
7. Show that:
(i) $\cos (\alpha-\beta)=\frac{1+\tan \alpha \tan \beta}{\sec \alpha \sec \beta}$
(ii) $\sin (\alpha+\beta)=\frac{1+\cot \alpha \tan \beta}{\cos \sec \alpha \sec \beta}$
(iii) $\cot (\alpha-\beta)=\frac{\cot \alpha \cot \beta+1}{\cot \beta-\cot \alpha}$
(iv) $\frac{\tan \alpha+\tan \beta}{\tan \alpha-\tan \beta}=\frac{\sin (\alpha+\beta)}{\sin (\alpha-\beta)}$
(v) $\cot (\alpha+\beta)=\frac{\cot \alpha \cot \beta-1}{\cot \alpha+\cot \beta}$
8. If $\sin \alpha=\frac{24}{25}$ and $\cos \beta=\frac{20}{29}$, where $0<\alpha<\frac{\pi}{2}$ and $0<\beta<\frac{\pi}{2}$.

Show that $\sin (\alpha-\beta)=\frac{333}{725}$.
9. If $\sin \alpha=-\frac{8}{17}$ and $\cos \beta=-\frac{4}{5}$ where $\frac{3 \pi}{2}<\alpha<2 \pi$ and $\pi<\beta<\frac{3 \pi}{2}$. Find
(i) $\sin (\alpha+\beta)$
(ii) $\cos (\alpha+\beta)$
(iii) $\tan (\alpha+\beta)$
(iv) $\sin (\alpha-\beta)$
(v) $\cos (\alpha-\beta)$
(vi) $\tan (\alpha-\beta)$.

In which quadrants do the terminal sides of the angles of measures $(\alpha+\beta)$ and $(\alpha-\beta)$ lip?
10. Find $\sin (\alpha+\beta)$ and $\cos (\alpha+\beta)$, given that
(i) $\tan \alpha=\frac{3}{4}, \cos \beta=\frac{5}{13}$ and neither the terminal side of the angle of measure $\alpha$ nor that of $\beta$ is in the quadrant I .
(ii) $\tan \alpha=-\frac{15}{8}$ and $\sin \beta=-\frac{7}{25}$ and neither the terminal side of the angle of measure $\alpha$ nor that of $\beta$ is in the quadrant IV.
11. Prove that: $\frac{\cos 19^{\circ}+\sin 19^{\circ}}{\cos 19^{\circ}-\sin 19^{\circ}}=\tan 64^{\circ}$.
12. Prove that: $\cos \left(60^{\circ}+\theta\right) \cos \left(60^{\circ}-\theta\right)+\sin \left(60^{\circ}+\theta\right) \sin \left(60^{\circ}-\theta\right)=\cos 2 \theta$

13. If $\alpha, \beta, \gamma$ are the angles of a triangle $A B C$, show that

$$
\cot \frac{\alpha}{2}+\cot \frac{\beta}{2}+\cot \frac{\gamma}{2}=\cot \frac{\alpha}{2} \cot \frac{\beta}{2} \cot \frac{\gamma}{2}
$$

14. If $\alpha+\beta+\gamma=180^{\circ}$, show that: $\cot \alpha \cot \beta+\cot \beta \cot \gamma+\cot \gamma \cot \alpha=1$
15. Express the following in the form $r \sin (\theta+\phi)$ or $r \sin (\theta-\phi)$ where terminal sides of the angles of measures $\theta$ and $\phi$ are in the first quadrant:
(i) $24 \sin \theta+7 \cos \theta$
(ii) $12 \sin \theta-5 \cos \theta$
(iii) $\sin \theta-\cos \theta$
(iv) $8 \sin \theta-6 \cos \theta$
(v) $\frac{1}{2} \sin \theta+\frac{\sqrt{3}}{2} \cos \theta$
(vi) $13 \sin \theta-84 \cos \theta$

# 10.4 Double Angle Identities 

We have discussed the following results:

$$
\begin{aligned}
& \sin (\alpha+\beta)=\sin \alpha \cos \beta+\cos \alpha \sin \beta \\
& \cos (\alpha+\beta)=\cos \alpha \cos \beta-\sin \alpha \sin \beta \quad \text { and } \quad \tan (\alpha+\beta)=\frac{\tan \alpha+\tan \beta}{1-\tan \alpha \tan \beta}
\end{aligned}
$$

We can use them to obtain the double angle identities as follows:
(i) Put $\beta=\alpha$ in $\sin (\alpha+\beta)=\sin \alpha \cos \beta+\cos \alpha \sin \beta$
$\sin (\alpha+\alpha)=\sin \alpha \cos \alpha+\cos \alpha \sin \alpha$
Hence $\sin 2 \alpha=2 \sin \alpha \cos \alpha$
(ii) Put $\beta=\alpha$ in $\cos (\alpha+\beta)=\cos \alpha \cos \beta-\sin \alpha \sin \beta$
$\cos (\alpha+\alpha)=\cos \alpha \cos \alpha-\sin \alpha \sin \alpha$
Hence $\cos 2 \alpha=\cos ^{2} \alpha-\sin ^{2} \alpha$
$\cos 2 \alpha=\cos ^{2} \alpha-\sin ^{2} \alpha$
$\cos 2 \alpha=\cos ^{2} \alpha-\left(1-\cos ^{2} \alpha\right) \quad\left(\because \sin ^{2} \alpha=1-\cos ^{2} \alpha\right)$

$$
=\cos ^{2} \alpha-1+\cos ^{2} \alpha
$$

$\cos 2 \alpha=2 \cos ^{2} \alpha-1$
$\cos 2 \alpha=\cos ^{2} \alpha-\sin ^{2} \alpha$
$\cos 2 \alpha=\left(1-\sin ^{2} \alpha\right)-\sin ^{2} \alpha \quad\left(\because \cos ^{2} \alpha=1-\sin ^{2} \alpha\right)$
$\cos 2 \alpha=1-2 \sin ^{2} \alpha$
(iii) Put $\beta=\alpha \ln \tan (\alpha+\beta)=\frac{\tan \alpha+\tan \beta}{1-\tan \alpha \tan \beta}$

$$
\begin{aligned}
\tan (\alpha+\alpha) & =\frac{\tan \alpha+\tan \alpha}{1-\tan \alpha \tan \alpha} \\
\tan 2 \alpha & =\frac{2 \tan \alpha}{1-\tan ^{2} \alpha}
\end{aligned}
$$

# 10.5 Half Angle Identities 

The formulas proved above can also be written in the form of half angle identities, in the following way:
(i) $\cos \alpha=2 \cos ^{2} \frac{\alpha}{2}-1 \Rightarrow \cos ^{2} \frac{\alpha}{2}=\frac{1+\cos \alpha}{2} \Rightarrow \cos \frac{\alpha}{2}= \pm \sqrt{\frac{1+\cos \alpha}{2}}$
(ii) $\cos \alpha=1-2 \sin ^{2} \frac{\alpha}{2} \Rightarrow \sin ^{2} \frac{\alpha}{2}=\frac{1-\cos \alpha}{2} \Rightarrow \sin \frac{\alpha}{2}= \pm \sqrt{\frac{1-\cos \alpha}{2}}$
(iii) $\tan \frac{\alpha}{2}=\frac{\sin \frac{\alpha}{2}}{\cos \frac{\alpha}{2}}= \pm \sqrt{\frac{1-\cos \alpha}{2}} \Rightarrow \tan \frac{\alpha}{2}= \pm \sqrt{\frac{1-\cos \alpha}{1+\cos \alpha}}$

### 10.6 Triple Angle Identities

(i) $\sin 3 \alpha=3 \sin \alpha-4 \sin ^{3} \alpha$
(ii) $\cos 3 \alpha=4 \cos ^{3} \alpha-3 \cos \alpha$
(iii) $\tan 3 \alpha=\frac{3 \tan \alpha-\tan ^{3} \alpha}{1-3 \tan ^{3} \alpha}$

Proof: (i) $\sin 3 \alpha=\sin (2 \alpha+\alpha)$

$$
\begin{aligned}
& =\sin 2 \alpha \cos \alpha+\cos 2 \alpha \sin \alpha \\
& =2 \sin \alpha \cos \alpha \cos \alpha+\left(1-2 \sin ^{2} \alpha\right) \sin \alpha \\
& =2 \sin \alpha \cos ^{2} \alpha+\sin \alpha-2 \sin ^{3} \alpha \\
& =2 \sin \alpha\left(1-\sin ^{2} \alpha\right)+\sin \alpha-2 \sin ^{3} \alpha \\
& =2 \sin \alpha-2 \sin ^{3} \alpha+\sin \alpha-2 \sin ^{3} \alpha \\
\sin 3 \alpha & =3 \sin \alpha-4 \sin ^{3} \alpha \\
\text { (ii) } \cos 3 \alpha & =\cos (2 \alpha+\alpha) \\
& =\cos 2 \alpha \cos \alpha-\sin 2 \alpha \sin \alpha \\
& =\left(2 \cos ^{2} \alpha-1\right) \cos \alpha-2 \sin \alpha \cos \alpha \sin \alpha \\
& =2 \cos ^{3} \alpha-\cos \alpha-2 \sin ^{2} \alpha \cos \alpha \\
& =2 \cos ^{3} \alpha-\cos \alpha-2\left(1-\cos ^{2} \alpha\right) \cos \alpha \\
& =2 \cos ^{3} \alpha-\cos \alpha-2 \cos \alpha+2 \cos ^{3} \alpha \\
\cos 3 \alpha & =4 \cos ^{3} \alpha-3 \cos \alpha
\end{aligned}
$$

(iii) $\tan 3 \alpha=\tan (2 \alpha+\alpha)$

$$
=\frac{\tan 2 \alpha+\tan \alpha}{1-\tan 2 \alpha \tan \alpha}
$$

# Unit 10 Trigonometric Identities <193 

$$
\begin{aligned}
& =\frac{\frac{2 \tan \alpha}{1-\tan ^{2} \alpha}+\tan \alpha}{1-\frac{2 \tan \alpha}{1-\tan ^{2} \alpha} \cdot \tan \alpha}=\frac{2 \tan \alpha+\tan \alpha-\tan ^{2} \alpha}{1-\tan ^{2} \alpha-2 \tan ^{2} \alpha} \\
& \tan ^{2} \alpha=\frac{3 \tan \alpha-\tan ^{3} \alpha}{1-3 \tan ^{2} \alpha}
\end{aligned}
$$

Example 11 Prove that: $\frac{\sin \theta+\sin 2 \theta}{1+\cos \theta+\cos 2 \theta}=\tan \theta$
Solution

$$
\begin{aligned}
\text { L.H.S. } & =\frac{\sin \theta+2 \sin \theta \cos \theta}{1+\cos \theta+2 \cos ^{2} \theta-1}=\frac{\sin \theta(1+2 \cos \theta)}{\cos \theta(1+2 \cos \theta)} \\
& =\frac{\sin \theta}{\cos \theta}=\tan \theta=\text { R.H.S. }
\end{aligned}
$$

Hence $\frac{\sin \theta+\sin 2 \theta}{1+\cos \theta+\cos 2 \theta}=\tan \theta$.
Example 12 Show that: (i) $\sin 2 \theta=\frac{2 \tan \theta}{1+\tan ^{2} \theta}$ (ii) $\cos 2 \theta=\frac{1-\tan ^{2} \theta}{1+\tan ^{2} \theta}$
Solution (i) $\sin 2 \theta=2 \sin \theta \cos \theta=\frac{2 \sin \theta \cos \theta}{1}=\frac{2 \sin \theta \cos \theta}{\cos ^{2} \theta+\sin ^{2} \theta}$

$$
=\frac{\frac{2 \sin \theta \cos \theta}{\cos ^{2} \theta}}{\frac{\cos ^{2} \theta+\sin ^{2} \theta}{\cos ^{2} \theta}}=\frac{2 \frac{\sin \theta}{\cos \theta}}{\frac{\cos ^{2} \theta}{\cos ^{2} \theta}+\frac{\sin ^{2} \theta}{\cos ^{2} \theta}}
$$

$$
\sin 2 \theta=\frac{2 \tan \theta}{1+\tan ^{2} \theta}
$$

(ii) $\cos 2 \theta=\cos ^{2} \theta-\sin ^{2} \theta=\frac{\cos ^{2} \theta-\sin ^{2} \theta}{1}=\frac{\cos ^{2} \theta-\sin ^{2} \theta}{\cos ^{2} \theta+\sin ^{2} \theta}$

$$
\begin{aligned}
& =\frac{\frac{\cos ^{2} \theta-\sin ^{2} \theta}{\cos ^{2} \theta}}{\frac{\cos ^{2} \theta+\sin ^{2} \theta}{\cos ^{2} \theta}}=\frac{\frac{\cos ^{2} \theta}{\cos ^{2} \theta}-\frac{\sin ^{2} \theta}{\cos ^{2} \theta}}{\frac{\cos ^{2} \theta}{\cos ^{2} \theta}+\frac{\sin ^{2} \theta}{\cos ^{2} \theta}} \\
\cos 2 \theta & =\frac{1-\tan ^{2} \theta}{1+\tan ^{2} \theta}
\end{aligned}
$$

Example 13 Reduce $\cos ^{4} \theta$ to an expression involving only function of multiples of $\theta$, raised to the first power.
Solution We know that:

$$
\begin{aligned}
2 \cos ^{2} \theta & =1+\cos 2 \theta \quad \Rightarrow \cos ^{2} \theta=\frac{1+\cos 2 \theta}{2} \\
\cos ^{4} \theta & =\left(\cos ^{2} \theta\right)^{2}=\left[\frac{1+\cos 2 \theta}{2}\right]^{2} \\
& =\frac{1+2 \cos 2 \theta+\cos ^{2} 2 \theta}{4} \\
& =\frac{1}{4}\left[1+2 \cos 2 \theta+\cos ^{2} 2 \theta\right] \\
& =\frac{1}{4}\left[1+2 \cos 2 \theta+\frac{1+\cos 4 \theta}{2}\right] \\
& =\frac{1}{4 \times 2}[2+4 \cos 2 \theta+1+\cos 4 \theta] \\
& =\frac{1}{8}[3+4 \cos 2 \theta+\cos 4 \theta]
\end{aligned}
$$

# EXERCISE 10.3 

1. Find the values of $\sin 2 \alpha, \cos 2 \alpha$ and $\tan 2 \alpha$, when:
(i) $\sin \alpha=\frac{3}{5}$
(ii) $\cos \alpha=\frac{4}{5}$, where $0<\alpha<\frac{\pi}{2}$
2. Prove the following identities:
(i) $\cot \alpha-\tan \alpha=2 \cot 2 \alpha$
(ii) $\frac{\sin 2 \alpha}{1+\cos 2 \alpha}=\tan \alpha$
(iii) $\frac{1-\cos \alpha}{\sin \alpha}=\tan \frac{\alpha}{2}$
(iv) $\frac{\cos \alpha-\sin \alpha}{\cos \alpha+\sin \alpha}=\sec 2 \alpha-\tan 2 \alpha$
(v) $\sqrt{\frac{1+\sin \alpha}{1-\sin \alpha}}=\frac{\sin \frac{\alpha}{2}+\cos \frac{\alpha}{2}}{\sin \frac{\alpha}{2}-\cos \frac{\alpha}{2}}$
(vi) $\frac{\operatorname{cosec} \theta+2 \operatorname{cosec} 2 \theta}{\sec \theta}=\cot \frac{\theta}{2}$
(vii) $1+\tan \alpha \tan 2 \alpha=\sec 2 \alpha$
(viii) $\frac{2 \sin \theta \sin 2 \theta}{\cos \theta+\cos 3 \theta}=\tan 2 \theta \tan \theta$

(ix) $\frac{\sin 3 \theta}{\sin \theta}-\frac{\cos 3 \theta}{\cos \theta}=2$
(x) $\frac{\cos 3 \theta}{\cos \theta}+\frac{\sin 3 \theta}{\sin \theta}=4 \cos 2 \theta$
(xi) $\frac{\tan \frac{\theta}{2}+\cot \frac{\theta}{2}}{\cot \frac{\theta}{2}-\tan \frac{\theta}{2}}=\sec \theta$
(xii) $\frac{\sin 3 \theta}{\cos \theta}+\frac{\cos 3 \theta}{\sin \theta}=2 \cot 2 \theta$
(xiii) $\frac{3+\cos 4 \theta}{1-\cos 4 \theta}=\frac{1}{2}\left(\tan ^{2} \theta+\cot ^{2} \theta\right)$
(xiv) $\frac{1+\sin 2 \theta}{1-\sin 2 \theta}=\tan ^{2}\left(\frac{\pi}{4}+\theta\right)$
(xv) $\cos ^{2} \frac{\pi}{8}+\cos ^{2} \frac{3 \pi}{8}+\cos ^{2} \frac{5 \pi}{8}+\cos ^{2} \frac{7 \pi}{8}=2$
3. Show that: $2 \cos \theta=\sqrt{2+\sqrt{2+2 \cos 4 \theta}}$
4. Reduce $\sin ^{4} \theta$ to an expression involving only function of multiples of $\theta$, raised to the first power.
5. Find the values of $\sin \theta$ and $\cos \theta$ without using table or calculator, when $\theta$ is:
(i) $18^{\circ}$
(ii) $36^{\circ}$
(iii) $54^{\circ}$
(iv) $72^{\circ}$

Hence prove that: $\cos 36^{\circ} \cos 72^{\circ} \cos 108^{\circ} \cos 144^{\circ}=\frac{1}{16}$

| Hint | Let $\theta=18^{\circ}$ | Let $\theta=36^{\circ}$ |
| :--: | :--: | :--: |
|  | $5 \theta=90^{\circ}$ | $5 \theta=180^{\circ}$ |
|  | $(3 \theta+2 \theta)=90^{\circ}$ | $3 \theta+2 \theta=180^{\circ}$ |
|  | $3 \theta=90^{\circ}-2 \theta$ | $3 \theta=180^{\circ}-2 \theta$ |
|  | $\sin 3 \theta=\sin \left(90^{\circ}-2 \theta\right)$ etc | $\sin 3 \theta=\sin \left(180^{\circ}-2 \theta\right)$ etc. |

# 10.7 Express the Product (of sines and cosines) as Sums or Differences (of sines and cosines) 

We know that:

$$
\begin{aligned}
& \sin (\alpha+\beta)=\sin \alpha \cos \beta+\cos \alpha \sin \beta \\
& \sin (\alpha-\beta)=\sin \alpha \cos \beta-\cos \alpha \sin \beta \\
& \cos (\alpha+\beta)=\cos \alpha \cos \beta-\sin \alpha \sin \beta \\
& \cos (\alpha-\beta)=\cos \alpha \cos \beta+\sin \alpha \sin \beta
\end{aligned}
$$

Adding (i) and (ii) we get

$$
\sin (\alpha+\beta)+\sin (\alpha-\beta)=2 \sin \alpha \cos \beta
$$

Subtracting (ii) from (i) we get

$$
\sin (\alpha+\beta)-\sin (\alpha-\beta)=2 \cos \alpha \sin \beta
$$

Adding (iii) and (iv) we get

$$
\cos (\alpha+\beta)+\cos (\alpha-\beta)=2 \cos \alpha \cos \beta
$$

Subtracting (iv) from (iii), we get

$$
\cos (\alpha+\beta)-\cos (\alpha-\beta)=-2 \sin \alpha \sin \beta
$$

So, we get four identities as:

$$
\begin{aligned}
& 2 \sin \alpha \cos \beta=\sin (\alpha+\beta)+\sin (\alpha-\beta) \\
& 2 \cos \alpha \sin \beta=\sin (\alpha+\beta)-\sin (\alpha-\beta) \\
& 2 \cos \alpha \cos \beta=\cos (\alpha+\beta)+\cos (\alpha-\beta) \\
& -2 \sin \alpha \sin \beta=\cos (\alpha+\beta)-\cos (\alpha-\beta)
\end{aligned}
$$

Now putting $\alpha+\beta=P$ and $\alpha-\beta=Q$, we get

$$
\begin{aligned}
& \alpha=\frac{P+Q}{2} \quad \text { and } \beta=\frac{P-Q}{2} \\
& \sin P+\sin Q=2 \sin \frac{P+Q}{2} \cos \frac{P-Q}{2} \\
& \sin P-\sin Q=2 \cos \frac{P+Q}{2} \sin \frac{P-Q}{2} \\
& \cos P+\cos Q=2 \cos \frac{P+Q}{2} \cos \frac{P-Q}{2} \\
& \cos P-\cos Q=-2 \sin \frac{P+Q}{2} \sin \frac{P-Q}{2}
\end{aligned}
$$

Example 14 Express $2 \sin 7 \theta \cos 3 \theta$ as a sum or difference.
Solution $2 \sin 7 \theta \cos 3 \theta=\sin (7 \theta+3 \theta)+\sin (7 \theta-3 \theta)$

$$
=\sin 10 \theta+\sin 4 \theta
$$

Example 15 Prove without using table / calculator, that

$$
\sin 10^{\circ} \cos 11^{\circ}+\sin 71^{\circ} \sin 11^{\circ}=\frac{1}{2}
$$

Solution L.H.S $=\sin 19^{\circ} \cos 11^{\circ}+\sin 71^{\circ} \sin 11^{\circ}$

$$
\begin{aligned}
& =\frac{1}{2}\left[2 \sin 19^{\circ} \cos 11^{\circ}+2 \sin 71^{\circ} \sin 11^{\circ}\right] \\
& =\frac{1}{2}\left[\left\{\sin \left(19^{\circ}+11^{\circ}\right)+\sin \left(19^{\circ}-11^{\circ}\right)\right\}-\left\{\cos \left(71^{\circ}+11^{\circ}\right)-\cos \left(71^{\circ}-11^{\circ}\right)\right\}\right] \\
& =\frac{1}{2}\left[\sin 30^{\circ}+\sin 8^{\circ}-\cos 82^{\circ}+\cos 60^{\circ}\right] \\
& =\frac{1}{2}\left[\frac{1}{2}+\sin 8^{\circ}-\cos \left(90^{\circ}-8^{\circ}\right)+\frac{1}{2}\right]
\end{aligned}
$$

$$
\begin{aligned}
& =\frac{1}{2}\left[\frac{1}{2}+\sin 8^{\circ}-\sin 8^{\circ}+\frac{1}{2}\right] \quad\left(\because \cos 82^{\circ}=\cos \left(90^{\circ}-8^{\circ}\right)=\sin 8^{\circ}\right) \\
& =\frac{1}{2}\left[\frac{1}{2}+\frac{1}{2}\right] \\
& =\frac{1}{2}=\text { R.H.S }
\end{aligned}
$$

Hence, $\sin 19^{\circ} \cos 11^{\circ}+\sin 71^{\circ} \sin 11^{\circ}=\frac{1}{2}$
Example 16 Expresn $\sin 5 x+\sin 7 x$ as a product.
Solution

$$
\begin{aligned}
\sin 5 x+\sin 7 x & =2 \sin \frac{5 x+7 x}{2} \cos \frac{5 x-7 x}{2}=2 \sin 6 x \cos (-x) \\
& =2 \sin 6 x \cos x \quad\left(\because \cos (- \theta)=\cos \theta\right)
\end{aligned}
$$

Example 17 Expresn $\cos \theta+\cos 3 \theta+\cos 5 \theta+\cos 7 \theta$ as a product.
Solution $\cos \theta+\cos 3 \theta+\cos 5 \theta+\cos 7 \theta$

$$
\begin{aligned}
& =(\cos 3 \theta+\cos \theta)+(\cos 7 \theta+\cos 5 \theta) \\
& =2 \cos \frac{3 \theta+\theta}{2} \cos \frac{3 \theta-\theta}{2}+2 \cos \frac{7 \theta+5 \theta}{2} \cos \frac{7 \theta-5 \theta}{2} \\
& =2 \cos 2 \theta \cos \theta+2 \cos 6 \theta \cos \theta \\
& =2 \cos \theta(\cos 6 \theta+\cos 2 \theta) \\
& =2 \cos \theta\left[2 \cos \frac{6 \theta+2 \theta}{2} \cos \frac{6 \theta-2 \theta}{2}\right] \\
& =2 \cos \theta(2 \cos 4 \theta \cos 2 \theta)=4 \cos \theta \cos 2 \theta \cos 4 \theta
\end{aligned}
$$

Example 18 Show that $\cos 20^{\circ} \cos 40^{\circ} \cos 80^{\circ}=\frac{1}{8}$
Solution L.H.S $=\cos 20^{\circ} \cos 40^{\circ} \cos 80^{\circ}$

$$
\begin{aligned}
& =\frac{1}{4}\left(4 \cos 20^{\circ} \cos 40^{\circ} \cos 80^{\circ}\right) \\
& =\frac{1}{4}\left[\left(2 \cos 40^{\circ} \cos 20^{\circ}\right) \cdot 2 \cos 80^{\circ}\right] \\
& =\frac{1}{4}\left[\left(\cos 60^{\circ}+\cos 20^{\circ}\right) \cdot 2 \cos 80^{\circ}\right] \\
& =\frac{1}{4}\left[\left(\frac{1}{2}+\cos 20^{\circ}\right) \cdot 2 \cos 80^{\circ}\right]
\end{aligned}
$$

$$
\begin{aligned}
& =\frac{1}{4}\left(\cos 80^{\circ}+2 \cos 80^{\circ} \cos 20^{\circ}\right) \\
& =\frac{1}{4}\left(\cos 80^{\circ}+\cos 100^{\circ}+\cos 60^{\circ}\right) \\
& =\frac{1}{4}\left[\cos 80^{\circ}+\cos \left(180^{\circ}-80^{\circ}\right)+\cos 60^{\circ}\right] \\
& =\frac{1}{4}\left[\cos 80^{\circ}-\cos 80^{\circ}+\frac{1}{2}\right] \quad\left[\because \cos \left(180^{\circ}-\theta\right)=-\cos \theta\right] \\
& =\frac{1}{4}\left(\frac{1}{2}\right)=\frac{1}{8}=\text { R.H.S }
\end{aligned}
$$

Hence, $\cos 20^{\circ} \cos 40^{\circ} \cos 80^{\circ}=\frac{1}{8}$

# EXERCISE 10.4 

1. Express the following products as sums or differences:
(i) $2 \sin 3 \theta \cos \theta$
(ii) $2 \cos 5 \theta \sin 3 \theta$
(iii) $\sin 5 \theta \cos 2 \theta$
(iv) $2 \sin 7 \theta \sin 2 \theta$
(v) $\cos (x+y) \sin (x-y)$
(vi) $\cos \left(2 x+30^{\circ}\right) \cos \left(2 x-30^{\circ}\right)$
(vii) $\sin 12^{\circ} \sin 46^{\circ}$
(viii) $\sin \left(x+45^{\circ}\right) \sin \left(x-45^{\circ}\right)$
2. Express the following sums or differences as products:
(i) $\sin 5 \theta+\sin 3 \theta$
(ii) $\sin 8 \theta-\sin 4 \theta$
(iii) $\cos 6 \theta+\cos 3 \theta$
(iv) $\cos 7 \theta-\cos \theta$
(v) $\cos 12^{\circ}+\cos 48^{\circ}$
(vi) $\sin \left(x+30^{\circ}\right)+\sin \left(x-30^{\circ}\right)$
3. Prove the following identities:
(i) $\frac{\sin 3 x-\sin x}{\cos x-\cos 3 x}=\cot 2 x$
(ii) $\frac{\sin 8 x+\sin 2 x}{\cos 8 x+\cos 2 x}=\tan 5 x$
(iii) $\frac{\sin A-\sin B}{\sin A+\sin B}=\tan \frac{A-B}{2} \cot \frac{A+B}{2}$
(iv) $\frac{\sin 80^{\circ}+\sin 40^{\circ}}{\cos 80^{\circ}+\cos 40^{\circ}}=\sqrt{3}$
4. Prove that:
(i) $\cos 15^{\circ}+\cos 105^{\circ}+\cos 195^{\circ}+\cos 160^{\circ}+\cos 285^{\circ}=0$
(ii) $\frac{\sin 2 \theta+\sin 4 \theta+\sin 6 \theta+\sin 8 \theta}{\cos 2 \theta+\cos 4 \theta+\cos 6 \theta+\cos 8 \theta}=\tan 5 \theta$

(iii) $\cos ^{2}\left(\frac{\pi}{4}-\frac{\alpha}{2}\right)-\cos ^{2}\left(\frac{\pi}{4}+\frac{\alpha}{2}\right)=\sin \alpha$
(iv) $\sin \left(\frac{\pi}{4}-\theta\right) \sin \left(\frac{\pi}{4}+\theta\right)=\frac{1}{2} \cos 2 \theta$
(v) $\frac{\sin \theta+\sin 3 \theta+\sin 5 \theta+\sin 7 \theta}{\cos \theta+\cos 3 \theta+\cos 5 \theta+\cos 7 \theta}=\tan 4 \theta$
5. Prove that:
(i) $\cos 20^{\circ} \cos 40^{\circ} \cos 60^{\circ} \cos 80^{\circ}=\frac{1}{16}$
(ii) $\sin \frac{\pi}{9} \sin \frac{2 \pi}{9} \sin \frac{\pi}{3} \sin \frac{4 \pi}{9}=\frac{3}{16}$
(iii) $\sin 10^{\circ} \sin 30^{\circ} \sin 50^{\circ} \sin 70^{\circ}=\frac{1}{16}$
6. Prove that: $\frac{\sin 3 \theta}{1+2 \cos 2 \theta}=\sin \theta$; deduce the value of $\sin 15^{\circ}$
7. Prove that: $\tan 75^{\circ}-\tan 15^{\circ}=2 \sqrt{3}$
8. Prove that: $\cos 15^{\circ}-\sin 15^{\circ}=\frac{1}{\sqrt{2}}$
9. Prove that: $\frac{\sin ^{2} \alpha-\sin ^{2} \beta}{\sin \alpha \cos \alpha-\sin \beta \cos \beta}=\tan (\alpha+\beta)$
10. Prove that:
$\sin \alpha+\sin \beta+\sin \gamma-\sin (\alpha+\beta+\gamma)=4 \sin \left(\frac{\alpha+\beta}{2}\right) \sin \left(\frac{\beta+\gamma}{2}\right) \sin \left(\frac{\gamma+\alpha}{2}\right)$

# Trigonometric Functions and their Graphs 

## INTRODUCTION

In this unit, students will explore key concepts essential for understanding the role of trigonometry in mathematics and its real-life applications. We will begin by learning how to determine the domain and range of trigonometric functions to understand their behavior. Next, we will discuss even and odd functions, along with their periodicity, which explains their repeating patterns.
Students will then learn how to graph and analyze sine, cosine, and tangent functions, following this, we will focus on calculating the maximum and minimum values of sinusoidal functions and examining their unique properties such as amplitude, frequency, and phase shifts.
Finally, students will apply these trigonometric concepts to solve practical problems in navigation, engineering, and physics, including calculating distances, optimizing solar panel angles, and analyzing forces in structures. Mastering these concepts will enable students to solve both theoretical and real-world problems using trigonometry.
Let us first find domains and ranges of trigonometric functions before drawing their graphs.

### 11.1 Domains and Ranges of Sine and Cosine Functions

We have already defined trigonometric functions $\sin \theta$, $\cos \theta, \tan \theta, \csc \theta, \sec \theta$ and $\cot \theta$. We know that if $P(x, y)$ is any point on unit circle with centre at the origin $O$ such that $m \angle X O P=\theta$ in standard position, then

$$
\cos \theta=x \quad \text { and } \sin \theta=y
$$

$\Rightarrow$ for any real number $\theta$ there is one and only one value of each $x$ and $y$ i.e., of each $\cos \theta$ and $\sin \theta$. Hence $\sin \theta$ and $\cos \theta$ are the functions of $\theta$ and their
[Image removed]

Figure 11.1
domain is $R$, the set of real numbers.
Since $P(x, y)$ is a point on the unit circle with centre at the origin $O$, therefore

$$
\begin{array}{lll}
-1 \leq x \leq 1 & \text { and } & -1 \leq y \leq 1 \\
\Rightarrow \quad-1 \leq \cos \theta \leq 1 & \text { and } & -1 \leq \sin \theta \leq 1
\end{array}
$$

Thus, the range of sine and cosine functions is $[-1,1]$.

# 11.1.1 Domains and Ranges of Tangent and Cotangent Functions 

From the Figure 11.1.
(i) $\tan \theta=\frac{y}{x}, x \neq 0$
$\Rightarrow$ terminal side $\overrightarrow{O P}$ should not coincide with $O Y$ or $O Y^{\prime}$ (the $Y$-axis)
$\Rightarrow \quad \theta \neq \pm \frac{\pi}{2}, \pm \frac{3 \pi}{2}, \pm \frac{5 \pi}{2}, \ldots$
$\Rightarrow \quad \theta \neq(2 n+1) \frac{\pi}{2}$, where $n \in Z$
Domain of tangent function $=R-\{x \mid x=(2 n+1) \frac{\pi}{2}, n \in Z\}$
If $y=\frac{1}{2}, \tan 0=\frac{1}{2 x}$ as $x \rightarrow 0, \frac{1}{2 x} \rightarrow \pm \infty$ therefore the range of tangent function $=R=$ set of real numbers.
(ii) From Figure 11.1

$$
\cot \theta=\frac{x}{y}, y \neq 0
$$

$\Rightarrow$ terminal side $\overrightarrow{O P}$ should not coincide with $O X$ or $O X^{\prime}$ (the $X$-axis)
$\Rightarrow \quad \theta \neq 0, \pm \pi, \pm 2 \pi, \ldots$
$\Rightarrow \quad \theta \neq n \pi$, where $n \in Z$
Domain of cotangent function $=R-\{x \mid x=n \pi, n \in Z\}$
If $x=\frac{1}{2}, \cot 0=\frac{1}{2 y}$ as $y \rightarrow 0, \frac{1}{2 y} \rightarrow \pm \infty$ therefore range of cotangent function $=R=$ set of real numbers.

### 11.1.2 Domain and Range of Secant Function

From the Figure 11.1

$$
\sec \theta=\frac{1}{x}, x \neq 0
$$

$\Rightarrow$ terminal side $\overrightarrow{O P}$ should not coincide with $O Y$ or $O Y^{\prime}$ (the $Y$-axis)
$\Rightarrow \quad \theta \neq \pm \frac{\pi}{2}, \pm \frac{3 \pi}{2}, \pm \frac{5 \pi}{2}, \ldots$
$\Rightarrow \quad \theta \neq(2 n+1) \frac{\pi}{2}$, where $n \in Z$
Domain of secant function $=R-\left\{x \mid x=(2 n+1) \frac{\pi}{2}, n \in Z\right\}$

As $0 \leq x \leq 1$ so, $\frac{1}{x} \geq 1, \sec \theta \geq 1$ and $-1 \leq x \leq 0$ so, $\frac{1}{x} \leq-1, \sec \theta \leq-1$
As $\sec \theta$ attains all real values except those between -1 and 1
Range of secant function $=R-\{x \mid-1<x<1\}$

# 11.1.3 Domain and Range of Cosccant Function 

From the Figure 11.1

$$
\csc \theta=\frac{1}{y}, y \neq 0
$$

$\Rightarrow$ terminal side $\overrightarrow{O P}$ should not coincide with $O X$ or $O X^{\prime}$ (the $X$-axis)
$\Rightarrow \theta \neq 0, \pm \pi, \pm 2 \pi, \ldots$
$\Rightarrow \theta \neq n \pi$, where $n \in Z$
Domain of cosccant function $=\mathrm{R}-\{x \mid x=n \pi, n \in Z\}$
As $\csc \theta$ attains all values except those between -1 and 1
Range of cosecant function $=\mathrm{R}-\{x \mid-1<x<1\}$
The following table summarizes the domains and ranges of the trigonometric functions:

| Function | Domain | Range |
| :-- | :-- | :-- |
| $y=\sin x$ | $(-\infty, \infty)=R$ | $[-1,1]$ |
| $y=\cos x$ | $(-\infty, \infty)=R$ | $[-1,1]$ |
| $y=\tan x$ | $R=(-\infty, \infty), x \neq(2 n+1) \frac{\pi}{2}, n \in Z$ | $(-\infty, \infty)=R$ |
| $y=\cot x$ | $R=(-\infty, \infty), x \neq n \pi, n \in Z$ | $(-\infty, \infty)=R$ |
| $y=\sec x$ | $(-\infty, \infty), x \neq(2 n+1) \frac{\pi}{2}, n \in Z$ | $(-\infty,-1] \cup[1, \infty)$ |
| $y=\operatorname{cosec} x$ | $(-\infty, \infty), x \neq n \pi, n \in Z$ | $(-\infty,-1] \cup[1, \infty)$ |

### 11.2 Even and Odd Functions

A function $f$ is said to be even if $f(-x)=f(x)$, for every number $x$ in the domain of $f$.
For example: $f(x)=x^{2}$ is even function of $x$. Here

$$
f(-x)=(-x)^{2}=x^{2}=f(x)
$$

## Remember!

The graph of even function is always symmetric about $y$-axis

A function $f$ is said to be odd if $f(-x)=-f(x)$, for every number $x$ in the domain of $f$.
For example: $f(x)=x^{3}$ is an odd function of $x$.
Here $f(-x)=(-x)^{3}=-x^{3}=-f(x)$
The function $f(\theta)=\cos \theta$ for all $\theta \in R$ is an even
[Image removed]
function (see figure 11.2).
Here $f(-\theta)=\cos (-\theta)=\cos \theta=f(\theta)$.
Thus, $f(\theta)=\cos \theta$ is an even function.
Similarly, the function $f(\theta)=\sin \theta$ for all $\theta \in R$ is an odd function.
Here $f(-\theta)=\sin (-\theta)=-\sin \theta=-f(\theta)$.
Thus, $f(\theta)=\sin \theta$ is an odd function.
[Image removed]

Note In both the cases, for each $x$ in the domain of $f,-x$ must also be in the domain of $f$.

# 11.3 Period of Trigonometric Functions 

All the six trigonometric functions repeat their values for each increase or decrease of $2 \pi$ in $\theta$ therefore, the values of trigonometric functions for $\theta$ and $\theta \pm 2 n \pi$, where $\theta \in \mathrm{R}$ and $n \in Z$, are the same. This behaviour of trigonometric functions is called periodicity.
Period of a trigonometric function is the smallest positive number which, when added to the original circular measure of the angle, gives the same value of the function. A function is periodic, if $f(\theta+p)=f(\theta)$, for all $\theta$ in domain of function and the least positive value of $p$ is called the period of the function.
Now, let us discover the periods of the trigonometric functions.
Theorem 11.1: Sine is a periodic function and its period is $2 \pi$.
Proof: Suppose $p$ is the period of sine function such that

$$
\sin (\theta+p)=\sin \theta \text { for all } \theta \in R
$$

Now put $\theta=0$, we have

$$
\begin{aligned}
\sin (0+p) & =\sin 0 \\
\Rightarrow \quad \sin p & =0 \\
\Rightarrow \quad p & =0,+\pi,+2 \pi,+3 \pi, \ldots
\end{aligned}
$$

(i) If $p=\pi$, then from (A)

$$
\sin (\theta+\pi)=\sin \theta \quad(\text { not true }) \quad \because \sin (\pi+\theta)=-\sin \theta
$$

Thus $\pi$ is not the period of $\sin \theta$
(ii) If $p=2 \pi$, then from (A)

$$
\sin (\theta+2 \pi)=\sin \theta, \quad \text { which is true } \quad \because \sin (0+2 \pi)=\sin 0
$$

As $2 \pi$ is the smallest positive real number for which

$$
\sin (\theta+2 \pi)=\sin \theta
$$

$2 \pi$ is the period of $\sin \theta$.
Theorem 11.2: Tangent is a periodic function and its period is $\pi$.
Proof: Suppose $p$ is the period of tangent function such that

$$
\begin{aligned}
& \tan (\theta+p)=\tan \theta \quad \text { for all } \theta \in \mathrm{R} \\
& p=0, \pi, 2 \pi, 3 \pi, \ldots
\end{aligned}
$$

(i) If $p=\pi$, then from (B) $\tan (\theta+\pi)=\tan \theta$, which is true
As $\pi$ is the smallest positive number for which $\tan (\theta+\pi)=\tan \theta$
Therefore, $\pi$ is the period of $\tan \theta$.

## Note

By adopting the procedure used in finding the periods of sine and tangent, we can prove that
(i) $2 \pi$ is the period of $\cos \theta$
(ii) $2 \pi$ is the period of $\sec \theta$
(iii) $2 \pi$ is the period of $\sec \theta$
(iv) $\pi$ is the period of $\cot \theta$

Example 1 Find the periods of:
(i) $\sin 2 x$
(ii) $3+\tan \frac{x}{3}$

Solution (i) We know that the period of sine is $2 \pi$

$$
\therefore \quad \sin (2 x+2 \pi)=\sin 2 x \quad \Rightarrow \quad \sin 2(x+\pi)=\sin 2 x
$$

It means that the value of $\sin 2 x$ repeats when $x$ is increased by $\pi$.
Hence $\pi$ is the period of $\sin 2 x$.
(ii) To find the period of $3+\tan \frac{x}{3}$, consider only $\tan \frac{x}{3}$.

We know that the period of tangent is $\pi$
$\tan \left(\frac{x}{3}+\pi\right)=\tan \frac{x}{3} \quad \Rightarrow \quad \tan \frac{1}{3}(x+3 \pi)=\tan \frac{x}{3}$
It means that the value of $\tan \frac{x}{3}$ repeats when $x$ is increased by $3 \pi$.
Hence the period of $3+\tan \frac{x}{3}$ is $3 \pi$. The addition of constant number 3 to the tangent function does not affect the period.

# EXERCISE 11.1 

1. Determine whether the following functions are even, odd or neither odd nor even.
(i) $\sin ^{2} x$
(ii) $\sin x+\cos x$
(iii) $\sin ^{4} x+\cos ^{4} x$
(iv) $\tan x+\sec x$
(v) $\frac{1}{\cos ^{2} x}$
(vi) $\frac{\sin x+\sin 3 x}{\cos x+\cos 3 x}$
(vii) $\frac{1}{\sec x+\sec ^{3} x}$
(viii) $\frac{1}{\sec x+\cot ^{2} x}$
2. Find the periods of the following functions:
(i) $\sin 5 x$
(ii) $\cos 7 x$
(iii) $\tan 3 x$
(iv) $\cot \frac{x}{2}$
(v) $19 \sin \left(\frac{\pi}{20} x\right)$
(vi) $\operatorname{cosec}\left(\frac{2 x}{5}\right)$
(vii) $\frac{1}{2} \sin \left(\frac{3 x}{2} \frac{\pi}{2}\right)$
(viii) $-5-3 \sec \left(7 \pi x+\frac{\pi}{4}\right)$
(ix) $12+10 \tan \left(\frac{\pi}{30} x\right)$
(x) $6-4 \cot \left(\frac{7 x}{4}+\frac{\pi}{4}\right)$
(xi) $9+30 \sec \left(\frac{x}{15}+\frac{2 \pi}{15}\right)$

### 11.4 Values of Trigonometric Functions

We know the values of trigonometric functions for angles of measure $0^{\circ}, 30^{\circ}, 45^{\circ}, 60^{\circ}$, and $90^{\circ}$. We have also established the following identities:

| $\sin (-\theta)=-\sin \theta$ | $\cos (-\theta)=\cos \theta$ | $\tan (-\theta)=-\tan \theta$ |
| :--: | :--: | :--: |
| $\sin (\pi-\theta)=\sin \theta$ | $\cos (\pi-\theta)=-\cos \theta$ | $\tan (\pi-\theta)=-\tan \theta$ |
| $\sin (\pi+\theta)=-\sin \theta$ | $\cos (\pi+\theta)=-\cos \theta$ | $\tan (\pi+\theta)=\tan \theta$ |
| $\sin (2 \pi-\theta)=-\sin \theta$ | $\cos (2 \pi-\theta)=\cos \theta$ | $\tan (2 \pi-\theta)=-\tan \theta$ |

By using the above identities, we can easily find the values of trigonometric functions of the angles of the following measures:

$$
\begin{array}{ll}
-30^{\circ},-45^{\circ},-60^{\circ},-90^{\circ} & \pm 120^{\circ}, \pm 135^{\circ}, \pm 150^{\circ}, \pm 180^{\circ} \\
\pm 210^{\circ}, \pm 225^{\circ}, \pm 240^{\circ}, \pm 270^{\circ} & \pm 300^{\circ}, \pm 315^{\circ}, \pm 330^{\circ}, \pm 360^{\circ}
\end{array}
$$

### 11.4.1 Graphs of Trigonometric Functions

To plot the graph we shall follow these steps:
(i) Table of ordered pairs $(x, y)$ is constructed, when $x$ is the measure of the angle and $y$ is the value of the trigonometric function for the angle of measure $x$.
(ii) The measures of the angles are taken along the $X$-axis.
(iii) The values of the trigonometric functions are taken along the $Y$-axis.

(iv) The points corresponding to the ordered pairs are plotted on the graph paper.
(v) These points are joined with the help of smooth curves.

# 11.4.2 Graph of $y=\sin x$ from $-2 \pi$ to $2 \pi$ 

We know that the period of sine function is $2 \pi$ so, we will first draw the graph for the interval from $0^{\circ}$ to $360^{\circ}$ (from 0 to $2 \pi$ ).

To graph the sine function, first, recall that $-1 \leq \sin x \leq 1$ for all $x \in R$.
We know the range of the sine function is $[-1,1]$, so the graph will be between the horizontal lines $y=+1$ and $y=-1$
The table of the ordered pairs satisfying $y=\sin x$ is as follows:

| $x$ | 0 <br> or <br> $0^{\circ}$ | $\begin{gathered} \pi \\ 6 \\ \text { or } \\ 30^{\circ} \end{gathered}$ | $\begin{gathered} \pi \\ 3 \\ \text { or } \\ 60^{\circ} \end{gathered}$ | $\begin{gathered} \pi \\ 2 \\ \text { or } \\ 90^{\circ} \end{gathered}$ | $\begin{gathered} 2 \pi \\ 3 \\ \text { or } \\ 120^{\circ} \end{gathered}$ | $\begin{gathered} 5 \pi \\ 6 \\ \text { or } \\ 150^{\circ} \end{gathered}$ | $\begin{gathered} \pi \\ 6 \\ \text { or } \\ 180^{\circ} \end{gathered}$ | $\begin{gathered} 7 \pi \\ 6 \\ \text { or } \\ 210^{\circ} \end{gathered}$ | $\begin{gathered} 4 \pi \\ 3 \\ \text { or } \\ 240^{\circ} \end{gathered}$ | $\begin{gathered} 3 \pi \\ 2 \\ \text { or } \\ 270^{\circ} \end{gathered}$ | $\begin{gathered} 5 \pi \\ 3 \\ \text { or } \\ 300^{\circ} \end{gathered}$ | $\begin{gathered} 11 \pi \\ 6 \\ \text { or } \\ 330^{\circ} \end{gathered}$ | $\begin{gathered} 2 \pi \\ 6 \\ \text { or } \\ 360^{\circ} \end{gathered}$ |
| :--: | :--: | :--: | :--: | :--: | :--: | :--: | :--: | :--: | :--: | :--: | :--: | :--: | :--: |
| $\operatorname{Sin} x$ | 0 | 0.5 | 0.87 | 1 | 0.87 | 0.5 | 0 | $-0.5$ | $-0.87$ | $-1$ | $-0.87$ | $-0.5$ | 0 |

To draw the graph:
(i) Take a convenient scale $\left\{\begin{array}{l}1 \text { side of small square on the } x \text {-axis }=10^{\circ} \\ 1 \text { side of big square on the } y \text {-axis }=1 \text { unit }\end{array}\right.$
(ii) Draw the coordinate axes.
(iii) Plot the points corresponding to the ordered pairs in the table above i.e., $(0,0),\left(30^{\circ}, 0.5\right),\left(60^{\circ}, 0.87\right)$ and so on.
(iv) Join the points with the help of a smooth curve as shown. So, we get the graph of $y=\sin x$ from 0 to $360^{\circ}$ i.e., from 0 to $2 \pi$.

Note As we see that the graphs of trigonometric functions are smooth curves and none of them is line segment or has sharp corners or breaks within their domain. This behaviour of the curve is called continuity. It means that the trigonometric functions are continuous, wherever they are defined. Moreover, as the trigonometric functions are periodic so their curves repeat after fixed intervals.
[Image removed]

In the similar way, we can draw the graph for the interval from $0^{\circ}$ to $-360^{\circ}$. This will complete the graph of $y=\sin x$ from $-360^{\circ}$ to $360^{\circ}$ (from $-2 \pi$ to $2 \pi$ ), which is given below:
[Image removed]

The graph in the interval $[0,2 \pi]$ is called a cycle and the maximum height of the wave from its mid line is called amplitude. Since the period of sine function is $2 \pi$, so the sine graph can be extended on both sides of $x$-axis through every interval of $2 \pi$.
Properties of graph of sine function $(y=\sin x)$
(i) The domain is the set of real numbers $(-\infty<x<\infty)$.
(ii) The range includes all real numbers from -1 to 1 , inclusive, $[-1,1]$.
(iii) The graph of sine function is continuous for all real numbers.
(iv) The period of sine function is $2 \pi$. Mathematically, we can express it as $\sin (\theta+2 \pi)=\sin \theta$
(v) The sine function is an odd function. As the graph of sine function is symmetric about the origin. Mathematically, it can be written as $\sin (-\theta)=-\sin \theta$.
(vi) The maximum value of $y=\sin x$ is 1 when $x=\frac{\pi}{2}+2 \pi n$, where $n \in \mathbb{Z}$.
(vii) The minimum value of $y=\sin x$ is -1 when $x=\frac{3 \pi}{2}+2 \pi n$, where $n \in \mathbb{Z}$.
(viii) The $x$-intercepts of the sine function occurs at $x=\pi n$, where $n \in \mathbb{Z}$.
(ix) The $y$-intercept of the sine function is 0 .
(x) The amplitude of sine function is 1 .
(xi) In unit circle $\sin \theta$ is equal to the $y$-coordinate of the given point.

# 11.4.3 Graph of $y=\cos x$ from $-2 \pi$ to $2 \pi$ 

We know that the period of cosine function is $2 \pi$ so, we will first draw the graph for the interval from $0^{\circ}$ to $360^{\circ}$ (from 0 to $2 \pi$ ).
We know the range of the cosine function is $[-1,1]$, so the graph will be between the horizontal lines $y=+1$ and $y=-1$.

The table of the ordered pairs satisfying $y=\cos x$ is as follows:

| $x$ | 0 | $\pi$ | $\pi$ | $\pi$ | $2 \pi$ | $5 \pi$ | $\pi$ | $7 \pi$ | $4 \pi$ | $3 \pi$ | $5 \pi$ | $11 \pi$ | $2 \pi$ |
| :--: | :--: | :--: | :--: | :--: | :--: | :--: | :--: | :--: | :--: | :--: | :--: | :--: | :--: |
|  | or | or | or | or | or | or | or | or | or | or | or | or | or |
|  | $0^{\circ}$ | $30^{\circ}$ | $60^{\circ}$ | $90^{\circ}$ | $120^{\circ}$ | $150^{\circ}$ | $180^{\circ}$ | $210^{\circ}$ | $240^{\circ}$ | $270^{\circ}$ | $300^{\circ}$ | $330^{\circ}$ | $360^{\circ}$ |
| $\cos x$ | 1 | 0.87 | 0.5 | 0 | $-0.5$ | $-0.87$ | -1 | $-0.87$ | $-0.5$ | 0 | 0.5 | 0.87 | 1 |

The graph of $y=\cos x$ from $0^{\circ}$ to $360^{\circ}$ is given below:
[Image removed]

In the similar way, we can draw the graph for the interval from $0^{\circ}$ to $-360^{\circ}$. This will complete the graph of $y=\cos x$ from $-360^{\circ}$ to $360^{\circ}$ i.e. from $-2 \pi$ to $2 \pi$, which is given below:
[Image removed]

As in the case of sine graph, the cosine graph is also extended on both sides of $x$-axis through an interval of $2 \pi$.
Properties of graph of cosine function $(y=\cos x)$
(i) The domain is the set of real numbers $(-\infty<x<\infty)$.
(ii) The range includes all real numbers from -1 to 1 , inclusive, $[-1,1]$.
(iii) The graph of cosine function is continuous for all real numbers.
(iv) The period of cosine function is $2 \pi$. Mathematically, we can express it as $\cos (\theta+2 \pi)=\cos \theta$

(v) The cosine function is an even function, as the graph of cosine function is symmetric about the $y$-axis. Mathematically, it can be written as $\cos (-\theta)=\cos \theta$.
(vi) The maximum value of $y=\cos x$ is 1 when $x=\pi n$, where $n$ is an even integer.
(vii) The minimum value of $y=\cos x$ is -1 when $x=\pi n$, where $n$ is an odd integer.
(viii) The $x$-intercepts of the cosine function occurs at $x=\frac{\pi}{2}+\pi n$, where $n \in \mathbf{Z}$.
(ix) The $y$-intercept of the cosine function is 1 .
(x) The amplitude of cosine function is 1 .
(xi) In unit circle $\cos \theta$ is equal to the $x$-coordinate of the given point.

# 11.4.4 Graph of $y=\tan x$ from $-\pi$ to $\pi$ 

We know that $\tan (-x)=-\tan x$ and $\tan (\pi-x)=-\tan x$, so the values of $\tan x$ for $x=0^{\circ}, 30^{\circ}, 60^{\circ}, 90^{\circ}$ can help us in making the table.
Also, we know that $\tan x$ is undefined at $x= \pm 90^{\circ}$, when
(i) $x$ approaches $\frac{\pi}{2}$ from left $x \rightarrow\left(\frac{\pi}{2}\right)^{-}$, $\tan x$ decreases indefinitely in Quard I.
(ii) $x$ approaches $\frac{\pi}{2}$ from right i.e., $x \rightarrow\left(\frac{\pi}{2}\right)^{+}$, $\tan x$ decreases indefinitely in Quard IV.
(iii) $x$ approaches $-\frac{\pi}{2}$ from left i.e., $x \rightarrow\left(-\frac{\pi}{2}\right)^{-}$, $\tan x$ increases indefinitely in Quard II.
(iv) $x$ approaches $-\frac{\pi}{2}$ from right i.e., $x \rightarrow\left(-\frac{\pi}{2}\right)^{+}$, $\tan x$ decreases indefinitely in Quard III.
We know that the period of tangent is $\pi$, so we shall first draw the graph for the interval from 0 to $\pi$ (from $0^{\circ}$ to $180^{\circ}$ ).
$\therefore \quad$ The table of ordered pairs satisfying $y=\tan x$ is given below:

| $x$ | 0 | $\frac{\pi}{6}$ | $\frac{\pi}{3}$ | $\frac{\pi}{2}-0$ | $\frac{\pi}{2}+0$ | $\frac{2 \pi}{3}$ | $\frac{5 \pi}{6}$ | $\pi$ |
| :--: | :--: | :--: | :--: | :--: | :--: | :--: | :--: | :--: |
|  | or | or | or | or | or | or | or | or |
|  | 0 | $30^{\circ}$ | $60^{\circ}$ | $90^{\circ}-0$ | $90^{\circ}+0$ | $120^{\circ}$ | $150^{\circ}$ | $180^{\circ}$ |
| $\tan x$ | 0 | 0.58 | 1.73 | $+\infty$ | $-\infty$ | $-1.73$ | $-0.58$ | 0 |

Since the period of $\tan x$ is $\pi$, so we have the following graph of $y=\tan x$ from $-360^{\circ}$ to $360^{\circ}$.
[Image removed]

Properties of graph of tangent function ( $y=\tan x$ )
(i) The domain is the set of real numbers except the values where function is undefined domain of $\tan x=(-\infty, \infty), x \neq(2 n+1) \frac{\pi}{2}$, where $n \in Z$
(ii) The range includes all real numbers $(-\infty, \infty)$
(iii) The graph of $\tan x$ is not continuous for all real numbers. It breaks at $x=(2 n+1) \frac{\pi}{2}$, where $n \in Z$
(iv) The period of tan function is $\pi$. Mathematically, we can express it as $\tan (\theta+\pi)=\tan \theta$
(v) The tan function is an odd function, as the graph of tan function is symmetric about the origin. Mathematically, it can be written as $\tan (-\theta)=-\tan \theta$
(vi) The $x$-intercepts of the tangent function occurs at $x=\pi n$, where $n \in \mathbb{Z}$.
(vii) The $y$-intercept of the tangent function is 0
(viii) The amplitude of tangent function is undefined because it has no maximum or minimum values.

# EXERCISE 11.2 

1. Draw the graph of each of the following function for the intervals mentioned against each:
(i) $y=-\sin 2 x, x \in[-2 \pi, 2 \pi]$
(ii) $y=2 \cos 2 x, x \in[-2 \pi, 2 \pi]$
(iii) $y=\tan 2 x, x \in[-\pi, \pi]$
(iv) $y=\tan \frac{x}{2}, x \in[-2 \pi, 2 \pi]$
(v) $y=\sin \frac{\pi}{2} x, x \in[0,2 \pi]$
(vi) $y=\cos \frac{\pi}{2} x \quad x \in[-\pi, \pi]$
2. On the same axes and to the same scale, draw the graphs of the following functions for their complete period:
(i) $y=\sin x$ and $y=\sin 2 x$
(ii) $y=\cos x$ and $y=\cos 2 x$
3. Solve graphically:
(i) $\sin x=\cos x, x \in[0, \pi]$
(ii) $\sin x=x, x \in[0, \pi]$

### 11.5 Maximum and Minimum Values of Given Functions of the Type

- $a+b \sin \theta$
- $a+b \cos \theta$
- $a+b \sin (c \theta+d)$
- $a+b \cos (c \theta+d)$
- The reciprocals of the above, where $a, b, c$ and $d$ are real numbers.

The trigonometric functions like sine and cosine are periodic function because the values of these function repeat over regular intervals. These functions are fundamental in mathematics because of the repetition of their values at definite cycles and are used to model various real-life situations, such as radio waves, light wave, and alternating current in electricity and are also known as a specific case of sinusoidal functions.
The functions of the form $f(\theta)=a+b \sin \theta, g(\theta)=a+b \cos \theta, f_{1}(\theta)=a+b \sin (c \theta+d)$ and $g_{1}(\theta)=a+b \cos (c \theta+d)$ are the types of sinusoidal functions.
Now consider the general form of sinusoidal function $f_{1}(\theta)=a+b \sin (c \theta+d) \ldots$ (i) here ' $a$ ' represent the vertical shift refers to the vertical translation of the graph of the function, achieved by shifting the entire graph upward or downward. This shift, also known as the vertical displacement, moves the function's position along the $y$-axis without altering its shape or period. Amplitude $|b|$ is the maximum height of a wave

measured from its midline. The period of (i) is equal to $\frac{2 \pi}{c}$. Phase shift ' $d$ ' indicates the horizontal translation of the graph of the function, determining how far the wave is shifted left or right along the $x$-axis. A positive $d$ shifts the graph to the left, while a negative $d$ shifts it to the right, altering the starting point of the wave without changing its shape or period.
For Example, consider the function $f(0)=1+3 \sin (2 \theta)$. Here $a=1$ is vertical shift, amplitude $=|b|=|3|=3$ and period $=\frac{2 \pi}{2}=\pi$ as shown in the adjacent figure.
[Image removed]

Now, finding the maximum and minimum values of the functions $f(\theta)=a+b \sin (c \theta+d)$ and $g(\theta)=a+b \cos (c \theta+d)$ is not a difficult task. We know that the maximum absolute values of sine and cosine are equal to 1 , so the maximum value of the product $b \sin \theta$ is $|b|$.
Thus, the maximum value of $f(0)$ or $g(\theta)$ is : $M=a+|b|$, whenever $\sin \theta=1$ or $\cos \theta=1$ where $M$ denotes the maximum value of the function.
The minimum value of $f(0)$ or $g(\theta)$ function is $m=a-|b|$, whenever $\sin \theta=-1$ or $\cos \theta=-1$ and $m$ denotes the minimum value of the function.

Note
The absolute value of $b$ is called the Amplitude of $f(\theta)=a+b \sin \theta$. The value of the amplitude can also be determined using the formula

$$
\text { Amplitude }=\frac{\text { Maximum value }- \text { Minimum value }}{2}
$$

Example 2 Find the maximum and minimum values of the following functions:
(i) $2+3 \sin x$
(ii) $5-2 \cos 3 x$
(iii) reciprocal of (ii)

Solution (i) Let $f(x)=2+3 \sin x$
The maximum value of $f(x)$ will occur when $\sin x=1$. Here $a=2$ and $b=3$,
Maximum value of the function: $M=a+|b|=2+3=5$
The minimum value of the function will occur when $\sin x=-1$.
Minimum value of the function: $m=a-|b|=2-3=-1$
Thus, maximum value of the function is 5 and the minimum value is -1

(ii) Let $f(x)=5-2 \cos 3 x$

The maximum value of $f(x)$ will occur when $\cos 3 x=1$. Here $a=5$ and $b=-2$,
Maximum value of the function: $M=a+|b|=5+|-2|=5+2=7$.
The minimum value of the function will occurs when $\cos 3 x=-1$.
Minimum value of the function: $m=a-|b|=5-|-2|=5-2=3$.
Thus, maximum value of the function is 7 and the minimum value is 3 .
(iii) reciprocal of part (ii)

The reciprocal of $5-2 \cos 3 x$ is $\frac{1}{5-2 \cos 3 x}$
Let $g(x)=\frac{1}{5-2 \cos 3 x}$
To find the maximum and minimum values of $g(x)$, first we will find the maximum and minimum values of $5-2 \cos 3 x$, which are 7 and 3 respectively.
After finding the maximum and minimum values take their reciprocal. The reciprocal of the maximum value is the minimum of $g(x)$ and the reoprocal of the
minimum value is the maximum of $g(x)$
Maximum value of $g(x)=\frac{1}{m}=\frac{1}{3}=0.33$
Minimum value of $g(x)=\frac{1}{M}=\frac{1}{7}=0.14$

# 11.5.1 Real World Applications 

## Ferris Wheel Problems

The first Ferris wheel was invented by George W. Ferris. He built the first one for 1893 World'a Fair. A Ferris wheel is an important example of periodic motion that can be described using trigonometric functions, specifically sinusoidal functions. When we model the height of a rider on a Ferris wheel over time, we can use these functions to capture the periodic nature of the motion. The motion of Ferris wheel can be modeled by $f(t)=a+b \sin (c t+d)$ or $f(t)=a+b \cos (c t+d)$.
[Image removed]

Example 3 A Ferris wheel with a radius of 45 feet has its lowest point located 5 feet above the ground. It completes one full revolution every 60 seconds in counter clock wise direction. Model an equation that describes the height of a rider on the Ferris wheel as a function of time $t$. How high is the rider from the ground after 40 seconds?. Also graph the model equation. Solution Since it takes 60 seconds for the Ferris wheel to complete one full revolution

(one cycle), which is the period of the Ferris wheel, that is period $=60$

$$
\frac{2 \pi}{c}=60 \quad \Rightarrow \quad c=\frac{2 \pi}{60} \quad \Rightarrow \quad c=\frac{\pi}{30}
$$

The amplitude $b$ which is equal to the radius of a ferris wheel (in this case $b=45$ ).
The vertical shift $a$ is the height of the center of the Ferris wheel above the ground. Since the lowest point is 5 feet above the ground, so $a=5+b=5+45=50$.
we can model the height of a rider using (sine or cosine), because it reflects the periodic nature of the motion. We usually choose a cosine function if the rider starts at the maximum or minimum height, or a sine function if the rider starts at the midpoint.
Since the rider starts at the lowest point and goes up, we can easily model the required equation as a negative cosine function so,
$h(t)=-b \cos (c t)+a$, where $t$ is time and $h$ is height.
Now substituting the above values we get the function $h(t)=-45 \cos \left(\frac{\pi}{30} t\right)+50$,
which is the required equation of Ferris wheel.
Next, we find the height of the rider at $t=40$ seconds.

$$
h(t)=-45 \cos \left(\frac{\pi}{30} t\right)+50
$$

For $\quad t=40$, we have

$$
h(40)=-45 \cos \left(\frac{\pi}{30}, 40\right)+50=72.5 \text { feet }
$$

Thus, height of rider after 40 second is 72.5 feet.
The graph of the model equation is shown below.
[Image removed]

Example 4 The water level L (in feet) of a tidal river varies throughout the day. Suppose the level of the tidal river can be modeled by the equation: $L(t)=8+4 \sin \left(\frac{\pi}{6} t\right)$, where $t$ denotes the time (in hours). The water level oscillates 4 feet above and below an average level of 8 feet.
(a) Find the water level at $t=3$ hours?
(b) What is the minimum water level?

Solution (a) Given equation of water level: $L(t)=8+4 \sin \left(\frac{\pi}{6} t\right)$
To find the water level, substitute $t=3$ into the equation

$$
\begin{aligned}
& L(3)=8+4 \sin \left(\frac{\pi}{6} \cdot 3\right)=8+4 \sin \left(\frac{\pi}{2}\right) \\
& L(3)=8+4(1)=12
\end{aligned}
$$

Thus, water level at $t=3$ hours is 12 feet.
(b) Now, to find the minimum water level, we need to determine when the sine function attains its minimum value. We know that the minimum value of $\sin t=-1$, substitute the $\sin \left(\frac{\pi}{6} t\right)=-1$ into the equation

$$
L(t)=8+4 \sin \left(\frac{\pi}{6} t\right)=8+4(-1)=8-4=4
$$

Thus, minimum water level of the tidal river is 4 feet.
Example 5 From a point 100 m above the surface of a lake, the angle of elevation of a peak of a cliff is found to be $15^{\circ}$ and the angle of depression of the image of the peak is $30^{\circ}$. Find the height of the peak.
Solution Let $A$ be the top of the peak $\overline{A M}$ and $\overline{M B}$ be its image. Let $P$ be the point of observation and $L$ be the point just below $P$ (on the surface of the lake).
From $P$, draw $\overline{P Q} \perp \overline{A M}$.
Let $m \overline{P Q}=y$ metres and $m \overline{A M}=h$ metres.
$\therefore \quad m \overline{A Q}=h-m \overline{Q M}=h-m \overline{P L}=h-100$
[Image removed]

From the figure,

$$
\tan 15^{\circ}=\frac{A Q}{P Q}=\frac{h-100}{y} \text { and } \tan 30^{\circ}=\frac{B Q}{P Q}=\frac{100+h}{y}
$$

By division, we get

$$
\frac{\tan 15^{\circ}}{\tan 30^{\circ}}=\frac{h-100}{h+100}
$$

By Componendo and Dividendo, we have

$$
\begin{aligned}
& \frac{\tan 15^{\circ}+\tan 30^{\circ}}{\tan 15^{\circ}-\tan 30^{\circ}}=\frac{h-100+h+100}{h-100-h-100}=\frac{2 h}{-200}=\frac{h}{-100} \\
& \therefore \quad h=\frac{\tan 30^{\circ}+\tan 15^{\circ}}{\tan 30^{\circ}-\tan 15^{\circ}} \times 100=[\begin{array}{c}
0.5774+0.2679 \\
0.5774-0.2679
\end{array}] \times 100 \\
& \Rightarrow h=273.1179
\end{aligned}
$$

Hence height of the peak $=273 \mathrm{~m}$. (approximately)

# EXERCISE 11.3 

1. Find the maximum and minimum values of the following functions:
(i) $3-\sin 3 x$
(ii) $3+\sin 2 x$
(iii) $\frac{1}{2}+\sin (5 x+\pi)$
(iv) $\frac{3}{2}+\cos \left(x-\frac{\pi}{4}\right)$
(v) $1-3 \cos 2 x$
(vi) $1+2 \sin \left(x+\frac{\pi}{6}\right)$
(vii) $\frac{1}{10-2 \sin 3 x}$
(viii) $\frac{1}{7+3 \cos (-2 x)}$
(ix) $\frac{1}{5-3 \cos (3 x-1)}$
2. The temperature T in degrees Celsius of a certain city varies throughout the day according to the equation $T(t)=\frac{13}{2} \sin \left(\frac{\pi}{6} t-\frac{\pi}{9}\right)+15$, where $t$ is the time in hours, with $t=0$ corresponding to midnight.
(a) Find the maximum and minimum temperature during the day.
(b) Find the temperature at $t=9$ hours ( $9: 00$ a.m.).
3. A man on the top of a 100 m high light-house is in line with two ships on the same side of it, whose angles of depression from the man are $17^{\circ}$ and $19^{\circ}$ respectively. Find the distance between the ships.
4. $P$ and $Q$ are two points in line with a tree. If the distance between $P$ and $Q$ be 30 m and the angles of elevation of the top of the tree at $P$ and $Q$ are $12^{\circ}$ and $15^{\circ}$ respectively, find the height of the tree.
5. A giant Ferris wheel has a diameter of 60 feet. The lowest point of the wheel is located 6 feet above the ground. The wheel completes one full revolution every 80 seconds.

(a) Model an equation that represent the height $h(t)$ of a rider on the Ferris wheel at any given time $t$.
(b) Find the maximum height of the rider.
(c) Find the height of the rider from the ground after 35 seconds.
6. A child is playing on a swing in a playground. The height $h(t)$ of the swing seat above the ground (in metres) at time $t$ (in seconds) is modeled by the function:
$h(t)=1.5+1.2 \sin (3 \pi t)$
(a) What is the maximum height reached by the swing seat?
(b) What is the minimum height reached by the swing seat?
(c) How long does it take for the swing to complete one full-back-and-forth motion (period)?
(d) At what time(s) does the swing seat first reach a height of 2.12 metres?
7. A carnival ride consists of a vertical wheel with a diameter of 40 feet. The centre of the wheel is 28 feet above the ground. The wheel rotates at a constant speed and takes 120 seconds to make one complete revolution. Model an equation that describes the height $h(t)$ of a rider on the wheel as a function of time $t$. How high is the rider from the ground after 90 seconds? At what times will the rider be 36 feet above the ground?
8. Suppose the temperature $T$ in degrees Fahrenheit of Lahore city in a month of December throughout the day can be modeled by the equation: $T=64+8 \sin \left(\frac{\pi}{12}(t-8)\right)$, where $t$ is the time in hours. The temperature oscillates 8 degrees above and below an average temperature of 64 degrees.
(a) Find the temperature at $t=9$ hours?
(b) At what time the temperature will be maximum?
(c) Calculate the maximum temperature.
9. Suppose the population of a coastal city follows a sinusoidal pattern due to seasonal migration. The population of the city over the course of a year can be modeled by the equation: $P(t)=70000+10000 \cos \left(\frac{\pi}{6} t-\frac{\pi}{2}\right), P(t)$ is the population at time $t$ ( $t$ is the time in months, with $t=0$ corresponding to January $1^{\text {st }}$ ), where $t$ denoted the months in a year.
(a) Find the population of the city at $t=7$ months.
(b) Find the maximum population.

# Limit and Continuity 

## INTRODUCTION

In mathematics, the concept of limit and continuity is foundational in understanding the behaviour of functions and sequences, especially when applied to real-world scenarios. This unit will introduce and explore how to demonstrate and find the limit of a sequence and a function, understand continuous and discontinuous functions, and apply these concepts in various contexts such as economics, finance, and natural sciences.

### 12.1 Limit of a Function

The concept of limit of a function is the basis on which the structure of calculus rests. Before the definition of the limit of a function, it is necessary to have a clear understanding of the following phrases.

### 12.1.1 Meaning of the Phrase " $x$ approaches zero"

Suppose a sequence $x_{n}=\frac{1}{n^{2}}$ assumes a sequence of values as:

$$
\frac{1}{2}, \frac{1}{2^{2}}, \frac{1}{2^{3}}, \frac{1}{2^{4}} \cdots, \frac{1}{2^{n}}, \cdots
$$

We can see that the sequence $x_{n}=\frac{1}{n^{2}}$ is becoming smaller and smaller as $n$ increases and can be made as small as we please by taking " $n$ " sufficiently large. In other words, $x_{n}=\frac{1}{n^{2}}$ becoming closer and closer to 0 as $n$ becoming large. This unending decrease of $x_{n}$ is denoted by $x_{n} \rightarrow 0$ and read as " $x_{n}$ approaches zero" or " $x_{n}$ tends to zero as $n \rightarrow \infty$. That is, the limit of the sequence $x_{n}$ is 0 .

### 12.1.2 Meaning of the Phrase " $x$ approaches infinity"

Suppose a sequence $x_{n}=10^{n}$ assumes values as $1,10,10^{2}, 10^{3}, \ldots, 10^{n}, \ldots$
It is clear that the sequence $x_{n}$ is becoming larger and larger as $n$ increases and can be made as large as we please by taking $n$ sufficiently large. This unending increase of the sequence $x_{n}$ is symbolically written as " $x_{n} \rightarrow \infty$ " and is read as " $x_{n}$ approaches infinity" or " $x_{n}$ tends to infinity" as $n \rightarrow \infty$

# 12.1.3 Meaning of the Phrase " $x$ approaches $a$ " 

Symbolically it is written as " $x \rightarrow a$ " which means that $x$ is sufficiently close to $a$ but different from the number $a$, from both the left and right sides of $a$ that is $x-a$ becomes smaller and smaller as we please but $x-a \neq 0$.

Point to remember:
The symbol $x \rightarrow 0$ is quite different from $x=0$.
$x \rightarrow 0$ means that $x$ is very close to zero but not actually zero.
$x=0$ means that $x$ is actually zero.

### 12.1.4 Concept of Limit of a Function

## (1) By Finding the Area of Circumscribed Regular Polygon

Consider a circle of unit radius which circumscribes a square (4-sided regular polygon) as shown in Figure 12.1.
The side of square is $\sqrt{2}$ and its area is 2 square units. It is clear that the area of inscribed 4 -sided polygon is less than the area of the circum-circle $\pi=3.142\left(\pi r^{2}=\pi(1)^{2}=\pi=3.142\right)$
[Image removed]

Figure 12.1: 4 -sided polygon
[Image removed]

Figure 12.2: 8 -sided polygon
[Image removed]

Figure 12.3:16-sided polygon

Bisecting the arcs between the vertices of the square, we get an inscribed 8 -sided regular polygon as shown in Figure 12.2. Its area is $2 \sqrt{2}=2.828$ square units which is closer to the area of circum-circle. A further similar bisection of the arcs gives an inscribed 16 -sided regular polygon as shown in Figure 12.3 with area 3.061 square units which is more closer to the area of circum-circle.
It follows that as " $n$ ", the number of sides of the inscribed polygon increases, the area of polygon increases and becoming near to 3.142 which is the area of circle of unit radius.

We express this situation by saying that the limiting value of the area of the inscribed polygon is the area of the circle as $n$ approaches infinity, i.e.,

Area of inscribed polygon $\rightarrow$ Area of circle as $n \rightarrow \infty$

# (ii) Numerical Approach 

Consider the function $f(x)=x^{3}$
The domain of $f(x)$ is the set of all real numbers.
Let us find the limit of $f(x)=x^{3}$ as $x$ approaches 2 .
The table of values of $f(x)$ for different values of $x$ as $x$ approaches 2 from left and right is as follows:

From left of $2 \longrightarrow 2$ from right of 2

| $x$ | 1 | 1.5 | 1.8 | 1.9 | 1.99 | 1.999 | 1.9999 | 2.0001 | 2.001 | 2.01 | 2.1 | 2.2 | 2.5 | 3 |
| :--: | :--: | :--: | :--: | :--: | :--: | :--: | :--: | :--: | :--: | :--: | :--: | :--: | :--: | :--: |
| $f(x)=x^{3}$ | 1 | 3.375 | 5.832 | 6.859 | 7.8806 | 7.8806 | 7.9988 | 8.0012 | 8.012 | 8.1206 | 9.261 | 10.648 | 15.625 | 27 |

The table shows that, as $x$ gets closer and closer to 2 (sufficiently close to 2 ), from both sides, $f(x)$ gets closer and closer to 8 .
We say that 8 is the limit of $f(x)$ when $x$ approaches 2 and is written as:

$$
f(x) \rightarrow 8 \text { as } x \rightarrow 2 \quad \text { or } \quad \lim _{x \rightarrow 2} x^{2}=8
$$

### 12.1.5 Limit of a Function

Let a function $f(x)$ be defined in an open interval near the number " $a$ " (need not be at a). If, as $x$ approaches " $a$ " from both left and right side of " $a$ " $f(x)$ approaches a specific number "L" then "L", is called the limit of $f(x)$ as $x$ approaches $a$. Symbolically it is written as:
$\lim _{x \rightarrow a} f(x)=\mathrm{L}$ read as "limit of $f(x)$ as $x \rightarrow a$, is $L$ ".
It is neither desirable nor practicable to find the limit of a function by numerical approach. We must be able to evaluate a limit in some mechanical way. The theorems on limits will serve this purpose. Their proofs will be discussed in higher classes.

### 12.1.6 Theorems on Limits of Functions

Let $f$ and $g$ be two functions for which $\operatorname{Lim}_{x \rightarrow a} f(x)=L$ and $\operatorname{Lim}_{x \rightarrow a} g(x)=M$, then
Theorem 1: (i) $\lim _{x \rightarrow a} x^{p}=a^{p}$, where $p>0$ and $p \in R$
(ii) $\lim _{x \rightarrow a} c=c$

Theorem 2: (a) The limit of the sum of two functions is equal to the sum of their limits.

$$
\operatorname{Lim}_{x \rightarrow a}[f(x)+g(x)]=\operatorname{Lim}_{x \rightarrow a} f(x)+\operatorname{Lim}_{x \rightarrow a} g(x)=L+M
$$

For example, $\operatorname{Lim}_{x \rightarrow 1}(x+5)=\operatorname{Lim}_{x \rightarrow 1} x+\operatorname{Lim}_{x \rightarrow 1} 5=1+5=6$

(b) The limit of the difference of two functions is equal to the difference of their limits.

$$
\operatorname{Lim}_{x \rightarrow a}[f(x)-g(x)]=\operatorname{Lim}_{x \rightarrow a} f(x)-\operatorname{Lim}_{x \rightarrow a} g(x)=L-M
$$

For example, $\quad \operatorname{Lim}_{x \rightarrow 3}(x-5)=\operatorname{Lim}_{x \rightarrow 3}(x)-\operatorname{Lim}_{x \rightarrow 3} 5=3-5=-2$
(c) If $k$ is any real number, then

$$
\operatorname{Lim}_{x \rightarrow a}[k f(x)]=k \operatorname{Lim}_{x \rightarrow a} f(x)=k L
$$

For example, $\operatorname{Lim}_{x \rightarrow 2}(3 x)=3 \operatorname{Lim}_{x \rightarrow 2}(x)=3(2)=6$
(d) The limit of the product of the functions is equal to the product of their limits.

$$
\operatorname{Lim}_{x \rightarrow a}[f(x) g(x)]=\operatorname{Lim}_{x \rightarrow a} f(x) \cdot \operatorname{Lim}_{x \rightarrow a} g(x)=L M
$$

For example, $\operatorname{Lim}_{x \rightarrow 1}(2 x)(x+4)=\operatorname{Lim}_{x \rightarrow 1}(2 x) \cdot \operatorname{Lim}_{x \rightarrow 1}(x+4)=(2)(5)=10$
(e) The limit of the quotient of the functions is equal to the quotient of their limits provided the limit of denominator is non-zero.

$$
\begin{aligned}
& \operatorname{Lim}_{x \rightarrow a}\left[\frac{f(x)}{g(x)}\right]=\frac{\operatorname{Lim}_{x \rightarrow a} f(x)}{\operatorname{Lim}_{x \rightarrow a} g(x)}=\frac{L}{M}, \text { provided } g(x) \neq 0 \text { in a neighborhood of } \\
& a \text { and } M \neq 0
\end{aligned}
$$

For example: $\operatorname{Lim}_{x \rightarrow 2}\left[\frac{3 x+4}{x+3}\right]=\frac{\operatorname{Lim}_{x \rightarrow 2}(3 x+4)}{\operatorname{Lim}_{x \rightarrow 2}(x+3)}=\frac{6+4}{2+3}=\frac{10}{5}=2$
(f) Limit of $[f(x)]^{\prime}$, where $n$ is an integer

$$
\operatorname{Lim}_{x \rightarrow a}[f(x)]^{\prime \prime}=\left[\operatorname{Lim}_{x \rightarrow a} f(x)\right]^{\prime \prime}=L^{n}
$$

For example, $\operatorname{Lim}_{x \rightarrow 4}(2 x-3)^{3}=\left(\operatorname{Lim}_{x \rightarrow 4}(2 x-3)\right)^{3}=(5)^{3}=125$
We conclude from the theorems on limits that limits are evaluated by merely substituting the number that $x$ approaches into the function.

# 12.2 Limits of Important Functions 

If by substituting the number that $x$ approaches into the function, we get $\binom{0}{0}$, then one possible way to evaluate the limits is as follows:
We simplify the given function by using algebraic techniques of making factors if possible and cancel the common factors. The method explained in the following important limits.

### 12.2.1 $\underline{\operatorname{Lim}} \frac{x^{n}-a^{n}}{x-a}=n a^{n-1}$ where $n$ is a non-zero integer and $a>0$

Case I: Suppose $n$ is a positive integer.
By substituting $x=a$, we get $\binom{0}{0}$ form, so we make factors as follows:

$$
\begin{aligned}
x^{n}-a^{n} & =(x-a)\left(x^{n-1}+a x^{n-2}+a^{2} x^{n-3}+\ldots+a^{n-1}\right) \\
\lim _{x \rightarrow a} \frac{x^{n}-a^{n}}{x-a} & =\lim _{x \rightarrow a} \frac{(x-a)\left(x^{n-1}+a x^{n-2}+a^{2} x^{n-3}+\ldots+a^{n-1}\right)}{x-a} \\
& =\operatorname{Lim}_{x \rightarrow a}\left(x^{n-1}+a x^{n-2}+a^{2} x^{n-3}+\ldots+a^{n-1}\right) \\
& =a^{n-1}+a \quad a^{n-2}+a^{2} a^{n-3}+a^{3} a^{n-4}+\ldots+a^{n-1} \\
& =a^{n-1}+a^{n-1}+a^{n-1}+a^{n-1} \ldots+a^{n-1}=n a^{n-1}
\end{aligned}
$$

Case II: Suppose $n$ is a negative integer (Say $n=-m$ ) where $m$ is a positive integer.

$$
\begin{aligned}
& \text { Now, } \quad \frac{x^{n}-a^{n}}{x-a}=\frac{x^{-n}-a^{-n}}{x-a}=\frac{\frac{1}{x^{m}}-\frac{1}{a^{m}}}{x-a}=\frac{\frac{a^{m}-x^{m}}{x^{n} a^{m}}}{x-a} \\
& \therefore \quad \operatorname{Lim}_{x \rightarrow a} \frac{x^{n}-a^{n}}{x-a}=\operatorname{Lim}_{x \rightarrow a}\left(\frac{-1}{x^{m} a^{m}}\right)\left(\frac{x^{n}-a^{m}}{x-a}\right) \\
& =\frac{-1}{a^{m} a^{m}}\left(m a^{m-1}\right) \quad \text { (by Case }-1 \text { ) } \\
& =-m a^{-m-1} \\
& \therefore \quad \operatorname{Lim}_{x \rightarrow a}\left(\frac{x^{n}-a^{n}}{x-a}\right)=n a^{n-1} \quad \because n=-m
\end{aligned}
$$

# 12.2.2 $\underline{\operatorname{Lim}}_{x \rightarrow 0} \frac{\sqrt{x+a}-\sqrt{a}}{x}=\frac{1}{2 \sqrt{a}}$, where $n$ is an integer and $a>0$. 

By substituting $x=0$, we have $\left(\frac{0}{0}\right)$ form, so rationalizing the numerator.

$$
\begin{aligned}
\lim _{x \rightarrow 0} \frac{\sqrt{x+a}-\sqrt{a}}{x} & =\lim _{x \rightarrow 0}\left(\frac{\sqrt{x+a}-\sqrt{a}}{x}\right)\left(\frac{\sqrt{x+a}+\sqrt{a}}{\sqrt{x+a}+\sqrt{a}}\right)=\lim _{x \rightarrow 0} \frac{x+a-a}{x(\sqrt{x+a}+\sqrt{a})} \\
& =\lim _{x \rightarrow 0}\left(\frac{1}{\sqrt{x+a}+\sqrt{a}}\right) \\
& =\lim _{x \rightarrow 0} \frac{1}{\sqrt{x+a}+\sqrt{a}}=\frac{1}{\sqrt{a}+\sqrt{a}}=\frac{1}{2 \sqrt{a}}
\end{aligned}
$$

Example 1 Evaluate: (i) $\quad \lim _{x \rightarrow 1} \frac{x^{2}-1}{x^{2}-x}$
(ii) $\quad \lim _{x \rightarrow 3} \frac{x-3}{\sqrt{x}-\sqrt{3}}$

Solution (i) $\quad \lim _{x \rightarrow 1} \frac{x^{2}-1}{x^{2}-x} \quad\left(\frac{0}{0}\right)$ form.

$$
\begin{aligned}
\lim _{x \rightarrow 1} \frac{x^{2}-1}{x^{2}-x} & =\lim _{x \rightarrow 1} \frac{(x-1)(x+1)}{x(x-1)}=\lim _{x \rightarrow 1} \frac{x+1}{x} \\
& =\frac{1+1}{1}=\frac{2}{1}=2
\end{aligned}
$$

(ii) $\quad \lim _{x \rightarrow 3} \frac{x-3}{\sqrt{x}-\sqrt{3}}=\underline{\operatorname{Lim}}_{x \rightarrow 3} \frac{(\sqrt{x}+\sqrt{3})(\sqrt{x}=\sqrt{3})}{(\sqrt{x}=\sqrt{3})}=\operatorname{Lim}_{x \rightarrow 3}(\sqrt{x}+\sqrt{3})=\sqrt{3}+\sqrt{3}=2 \sqrt{3}$

### 12.2.3 Limit at Infinity

We have studied the limits of the functions $f(x), f(x) . g(x)$ and $\frac{f(x)}{g(x)}$, when $x \rightarrow c$ (a number)
Let us see what happens to the limit of the function $f(x)$ if $c$ is $+\infty$ or $-\infty$ (limits at infinity) i.e., when $x \rightarrow+\infty$ or $x \rightarrow-\infty$.
(a) Limit as $x \rightarrow+\infty$

Let $f(x)=\frac{1}{x}$, when $x \neq 0$
This function has the property that the value of $f(x)$ can be made as close as we please to zero when the number $x$ is sufficiently large.
We express this phenomenon by writing $\operatorname{Lim}_{x \rightarrow \infty} \frac{1}{x}=0$

(b) Limit as $x \rightarrow-\infty$

This type of limits are handled in the same way as limits as $x \rightarrow+\infty$.
i.e., $\operatorname{Lim}_{x \rightarrow-\infty} \frac{1}{x}=0$, where $x \neq 0$.

The following theorem is useful for evaluating limit at infinity.
Theorem: Let $p$ be a positive rational number. If $x^{p}$ is defined, then
$\operatorname{Lim}_{x \rightarrow+\infty} \frac{a}{x^{p}}=0$ and $\operatorname{Lim}_{x \rightarrow-\infty} \frac{a}{x^{p}}=0$, where $a$ is any real number.
For example, $\quad \operatorname{Lim}_{x \rightarrow+\infty} \frac{6}{x^{3}}=0$ and $\operatorname{Lim}_{x \rightarrow+\infty} \frac{-5}{\sqrt[3]{x}}=0$

# 12.2.4 Limit of a Sequence 

Let $\left\{a_{n}\right\}$ be a sequence, the limit of a sequence $\left\{a_{n}\right\}$ is the value $L$ that the terms of the sequence approach as $n \rightarrow \infty$, that is,

$$
\operatorname{Lim}_{n \rightarrow \infty} a_{n}=L
$$

If such an $L$ exists, the sequence is said to converge to $L$ and $\left\{a_{n}\right\}$ is called convergent sequence. If no such $L$ exists, the sequence is said to diverge.
For example, consider the sequence $\left\{a_{n}=\frac{1}{n}\right\}$ : As $n \rightarrow \infty, \frac{1}{n} \rightarrow 0$
So, we write $\operatorname{Lim}_{n \rightarrow \infty} a_{n}=\operatorname{Lim}_{n \rightarrow \infty} \frac{1}{n}=0$.
Example 2 Find the limit of the sequence $a_{n}=\frac{2 n+3}{n+1}$.
Solution We can simplify the sequence:

$$
a_{n}=\frac{2 n+3}{n+1}=\frac{n\left(2+\frac{3}{n}\right)}{n\left(1+\frac{1}{n}\right)}=\frac{2+\frac{3}{n}}{1+\frac{1}{n}}
$$

As $n \rightarrow \infty, \frac{3}{n} \rightarrow 0$ and $\frac{1}{n} \rightarrow 0$, so we are left with: $\operatorname{Lim}_{n \rightarrow \infty} a_{n}=\frac{2+0}{1+0}=2$

$$
\text { Thus, } \operatorname{Lim}_{n \rightarrow \infty} \frac{2 n+3}{n+1}=2
$$

Divergent Sequences: A sequence is divergent if it is not convergent. Divergence can occur in the following ways:

- The sequence may increase or decrease without bound (e.g., $a_{n}=n^{2}$ diverges to infinity).
- The sequence may oscillate between different values and not settle near any one value (e.g., $a_{n}=(-1)^{n}$ oscillates between -1 and 1 , so it does not converge).


# 12.2.5 Methods for Evaluating the Limits at Infinity 

In this case we first divide each term of both the numerator and the denominator by the highest power of $x$ that appears in the denominator and then use the theorems on limit.

Example 3 Evaluate $\operatorname{Lim}_{x \rightarrow+\infty} \frac{5 x^{4}-10 x^{2}+1}{-3 x^{3}+10 x^{2}+50}$
Solution Dividing numerator and denominator by $x^{3}$, we get
$\operatorname{Lim}_{x \rightarrow+\infty} \frac{5 x^{4}-10 x^{2}+1}{-3 x^{3}+10 x^{2}+50}=\operatorname{Lim}_{x \rightarrow+\infty} \frac{5 x-\frac{10}{x}+\frac{1}{x^{3}}}{-3+\frac{10}{x}+\frac{50}{x^{3}}}=\frac{\infty-0+0}{-3+0+0}=-\infty: \lim _{x \rightarrow \infty} \frac{a}{x^{a}}=0$
Example 4 Evaluate $\operatorname{Lim}_{x \rightarrow-\infty} \frac{4 x^{4}-5 x^{3}}{-3 x^{3}+2 x^{2}+1}$
Solution Dividing numerator and denominator by $x^{2}$, we get

$$
\operatorname{Lim}_{x \rightarrow-\infty} \frac{4 x^{4}-5 x^{3}}{-3 x^{3}+2 x^{2}+1}=\operatorname{Lim}_{x \rightarrow-\infty} \frac{\frac{4}{x}-\frac{5}{x^{2}}}{-3+\frac{2}{x^{3}}+\frac{1}{x^{3}}}=\frac{0-0}{-3+0+0}=0
$$

Example 5 Evaluate:
(i) $\quad \operatorname{Lim}_{x \rightarrow-\infty} \frac{2-3 x}{\sqrt{3}+4 x^{3}}$
(ii) $\quad \operatorname{Lim}_{x \rightarrow+\infty} \frac{2-3 x}{\sqrt{3}+4 x^{2}}$

Solution
(i) Here $\sqrt{x^{2}}=|x|=-x$ as $x<0$
$\therefore \quad$ Dividing numerator and denominator by $-x$, we get

$$
\operatorname{Lim}_{x \rightarrow-\infty} \frac{2-3 x}{\sqrt{3}+4 x^{2}}=\operatorname{Lim}_{x \rightarrow-\infty} \frac{-\frac{2}{x}+3}{\sqrt{\frac{3}{x^{2}}+4}}=\frac{0+3}{\sqrt{0+4}}=\frac{3}{2}
$$

(ii) Here $\sqrt{x^{2}}=|x|=x$ as $x>0$
$\therefore \quad$ Dividing numerator and denominator by $x$, we get

$$
\lim _{x \rightarrow+\infty} \frac{2-3 x}{\sqrt{3+4 x^{2}}}=\operatorname{Lim}_{x \rightarrow+\infty} \frac{\frac{2}{x}-3}{\sqrt{\frac{3}{x^{2}}+4}}=\frac{0-3}{\sqrt{0+4}}=\frac{-3}{2}
$$

12.2.6 $\quad \operatorname{Lim}_{n \rightarrow+\infty}\left(1+\frac{1}{n}\right)^{n}=e$

By the binomial theorem, we have

$$
\begin{aligned}
\left(1+\frac{1}{n}\right)^{n} & =1+n\left(\frac{1}{n}\right)+\frac{n(n-1)}{2!}\left(\frac{1}{n}\right)^{2}+\frac{n(n-1)(n-2)}{3!}\left(\frac{1}{n}\right)^{3}+\ldots \\
& =1+1+\frac{1}{2!}\left(1-\frac{1}{n}\right)+\frac{1}{3!}\left(1-\frac{1}{n}\right)\left(1-\frac{2}{n}\right)+\ldots
\end{aligned}
$$

When $n \rightarrow+\infty, \frac{1}{n}, \frac{2}{n}, \frac{3}{n}, \ldots$ all tends to zero, therefore

$$
\begin{aligned}
\therefore \quad \operatorname{Lim}_{x \rightarrow+\infty}\left(1+\frac{1}{n}\right)^{n} & =1+1+\frac{1}{2!}+\frac{1}{3!}+\frac{1}{4!}+\ldots \\
& =1+1+0.5+0.166667+0.0416667+\ldots=2.718281 \ldots
\end{aligned}
$$

As approximate value of $e$ is 2.718281 .

$$
\therefore \quad \operatorname{Lim}_{n \rightarrow+\infty}\left(1+\frac{1}{n}\right)^{n}=e
$$

Deduction: $\quad \operatorname{Lim}_{x \rightarrow 0}(1+x)^{x}=e$
We know that $\operatorname{Lim}_{n \rightarrow \infty}\left(1+\frac{1}{n}\right)^{n}=e$
(i)

Put $n=\frac{1}{x}$ in (i) then $x=\frac{1}{n}$
When $n \rightarrow \infty, x \rightarrow 0 \quad$ so, $\quad \operatorname{Lim}_{n \rightarrow+\infty}\left(1+\frac{1}{n}\right)^{n}=\operatorname{Lim}_{x \rightarrow 0}(1+x)^{\frac{1}{x}}$

$$
e=\operatorname{Lim}_{x \rightarrow 0}(1+x)^{\frac{1}{x}} \quad \because \quad \operatorname{Lim}_{x \rightarrow 1}\left(1+\frac{1}{n}\right)^{n}=e
$$

Hence $\operatorname{Lim}_{x \rightarrow 0}(1+x)^{\frac{1}{x}}=e$

# 12.2.7 $\lim _{x \rightarrow 0} \frac{a^{x}-1}{x}=\log _{a} a$ 

Put $a^{x}-1=y$
then $\quad a^{x}=1+y$
So, $\quad x=\log _{a}(1+y)$
From (i) when $x \rightarrow 0, y \rightarrow 0$

$$
\begin{aligned}
\therefore \quad \lim _{x \rightarrow 0} \frac{a^{x}-1}{x} & =\lim _{y \rightarrow 0} \frac{y}{\log _{a}(1+y)}=\underline{\lim _{y \rightarrow 0}} \frac{1}{\frac{1}{y} \log _{a}(1+y)} \\
& =\underline{\lim _{y \rightarrow 0}} \frac{1}{\log _{a}(1+y)^{y}}=\frac{1}{\log _{a} e}=\log _{a} a \quad\left(\underline{\lim _{y \rightarrow 0}(1+y)^{y}}=e\right)
\end{aligned}
$$

Deduction: $\quad \underline{\lim _{x \rightarrow 0}}\left(\frac{e^{x}-1}{x}\right)=\log _{e} e=1$
We know that $\underline{\lim _{x \rightarrow 0}}\left(\frac{a^{x}-1}{x}\right)=\log _{a} a$
Put $a=e$ in (i) we know $\operatorname{Lim}_{x \rightarrow 0}\left(\frac{e^{x}-1}{x}\right)=\log _{e} e=1$
Important Results to Remember
(i) $\quad \operatorname{Lim}_{x \rightarrow \infty} e^{x}=\infty$
(ii) $\quad \operatorname{Lim}_{x \rightarrow-\infty} e^{x}=\operatorname{Lim}_{x \rightarrow \infty}\left(\frac{1}{e^{x}}\right)=0$

## Example 6 Express each limit in terms of $e$.

(i) $\quad \lim _{n \rightarrow \infty}\left(1+\frac{3}{n}\right)^{3 n}$
(ii) $\quad \operatorname{Lim}_{n \rightarrow 0}(1+2 n)^{\frac{1}{n}}$

Solution (i) Observe the resemblance of the limit with $\operatorname{Lim}_{n \rightarrow \infty}\left(1+\frac{1}{n}\right)^{n}=e$

$$
\begin{aligned}
& \left(1+\frac{3}{n}\right)^{2 n}=\left[\left(1+\frac{3}{n}\right)^{\frac{n}{3}}\right]^{6}=\left[\left(1+\frac{1}{\frac{n}{3}}\right)^{\frac{n}{3}}\right]^{6} \\
& \because \quad \operatorname{Lim}_{n \rightarrow+\infty}\left(1+\frac{3}{n}\right)^{3 n}=\operatorname{Lim}_{m \rightarrow+\infty}\left[\left(1+\frac{1}{m}\right)^{m}\right]^{6}=e^{6} \text { where, } m=\frac{n}{3}
\end{aligned}
$$

(ii) Observe the resemblance of the limit with $\operatorname{Lim}_{x \rightarrow 0}(1+x)^{\frac{1}{x}}=e$

$$
\begin{aligned}
& \operatorname{Lim}_{n \rightarrow 0}(1+2 n)^{\frac{1}{n}}=\operatorname{Lim}_{n \rightarrow 0}\left[(1+2 n)^{\frac{1}{2 n}}\right]^{2} \\
& \text { put } m=2 n \text {, when } n \rightarrow 0, m \rightarrow 0 \\
& \operatorname{Lim}_{n \rightarrow 0}(1+2 n)^{\frac{1}{n}}=\lim _{m \rightarrow 0}\left[(1+m)^{\frac{1}{m}}\right]^{2}=e^{2}
\end{aligned}
$$

# 12.2.8 The Sandwich Theorem 

Let $f, g$ and $h$ be functions such that $f(x) \leq g(x) \leq h(x)$ for all numbers $x$ in some open interval containing " $c$ ", except possibly at $c$ itself.
If $\operatorname{Lim}_{x \rightarrow c} f(x)=L$ and $\operatorname{Lim}_{x \rightarrow c} h(x)=L$, then $\operatorname{Lim}_{x \rightarrow c} g(x)=L$
Many limit problems arise that cannot be directly evaluated by algebraic techniques. They require geometric arguments, so we evaluate an important theorem.

### 12.2.9 If $\theta$ is measured in radian, then $1 \operatorname{lin} \sin \theta=1$.

Proof: To evaluate this limit, we apply a new technique. Take $\theta$ be positive acute central angle of a sector of a circle with radius $r=1$. As shown in the figure, $O A B$ represents a sector of a circle. Join $A$ and $B$ and extend $O B$ to $D$ such that $O A \perp \overline{A D}$. Also draw $\overline{B C} \perp \overline{O C}$ on $\overline{O A}$.
Given $|O A|=|O B|=1 \quad$ (radii of unit circle)
In the right $\triangle O C B, \sin \theta=\frac{|\overline{B C}|}{\mid \overline{O B}} \mid=|\overline{B C}|$
In the right $\triangle O A D, \tan \theta=\frac{|\overline{A D}|}{|\overline{O A}|}=|\overline{A D}|$
(i) Area of $\triangle O A B=\frac{1}{2}|\overline{O A}||\overline{B C}|=\frac{1}{2}(1)(\sin \theta)=\frac{1}{2} \sin \theta$
(ii) Area of sector $O A B=\frac{1}{2} r^{2} \theta=\frac{1}{2}(1)(\theta)=\frac{1}{2} \theta \quad$ and
(iii) Area of $\triangle O A D=\frac{1}{2}|\overline{O A}||\overline{A D}|=\frac{1}{2}(1)(\tan \theta)=\frac{1}{2} \tan \theta$

From the figure we see that
Area of $\triangle O A B<$ Area of sector $O A B<$ Area of $\triangle O A D$
[Image removed]

Figure 12.4
$\Rightarrow \quad \frac{1}{2} \sin \theta<\frac{\theta}{2}<\frac{1}{2} \tan \theta$

As $\sin \theta$ is positive, so on division by $\frac{1}{2} \sin \theta$, we get

$$
1<\frac{\theta}{\sin \theta}<\frac{1}{\cos \theta} \quad\left(0<\theta<\frac{\pi}{2}\right)
$$

i.e., $\quad 1>\frac{\sin \theta}{\theta}>\cos \theta \quad$ or $\quad \cos \theta<\frac{\sin \theta}{\theta}<1$
when $\theta \rightarrow 0, \cos \theta \rightarrow 1$
Since $\frac{\sin \theta}{\theta}$ is sandwiched between 1 and a quantity approaching 1 itself. So, by the sandwich theorem, it must also approach 1 that is, $\operatorname{Lim}_{\theta \rightarrow 0} \frac{\sin \theta}{\theta}=1$

# Example 7 Evaluate $\operatorname{Lim}_{\theta \rightarrow 0} \frac{\sin 7 \theta}{\theta}$ 

Solution
Let $x=7 \theta$, so that $\theta=\frac{x}{7}$
when $\theta \rightarrow 0$ we have $x \rightarrow 0$

$$
\therefore \quad \lim _{x \rightarrow 0} \frac{\sin 7 \theta}{\theta}=\operatorname{Lim}_{x \rightarrow 0} \frac{\sin x}{x}=7 \operatorname{Lim}_{x \rightarrow 0} \frac{\sin x}{x}=(7)(1)=7
$$

Example 8 Evaluate $\operatorname{Lim}_{\theta \rightarrow 0} \frac{1-\cos \theta}{\theta}$
Solution $\frac{1-\cos \theta}{\theta}=\frac{1-\cos \theta}{\theta} \cdot \frac{1+\cos \theta}{1+\cos \theta}=\frac{1-\cos ^{2} \theta}{\theta(1+\cos \theta)}$

$$
=\frac{\sin ^{2} \theta}{\theta(1+\cos \theta)}=\sin \theta\left(\frac{\sin \theta}{\theta}\right)\left(\frac{1}{1+\cos \theta}\right)
$$

$\operatorname{Lim}_{\theta \rightarrow 0}\left(\frac{1-\cos \theta}{0}\right)=\operatorname{Lim}_{\theta \rightarrow 0} \sin \theta \cdot \operatorname{Lim}_{\theta \rightarrow 0} \frac{\sin \theta}{\theta} \cdot \operatorname{Lim}_{\theta \rightarrow 0}\left(\frac{1}{1+\cos \theta}\right)=(0)(1)\left(\frac{1}{1+1}\right)=0$

## EXERCISE 12.1

1. Find the limit of the following sequences if exists:
(i) $a_{n}=\frac{2 n+3}{n+1}$
(ii) $b_{n}=\frac{2 n+3}{n^{2}+1}$
(iii) $c_{n}=\frac{5 n^{2}}{2 n+3}$
(iv) $d_{n}=\frac{n^{2}-3 n+1}{2 n^{2}+n+4}$

2. Evaluate each limit by using theorems of limits:
(i) $\quad \underline{\operatorname{Lim}}_{x \rightarrow 3}(2 x+4)$
(ii) $\quad \underline{\operatorname{Lim}}_{x \rightarrow 1}\left(3 x^{2}-2 x+4\right)$
(iii) $\underline{\operatorname{Lim}}_{x \rightarrow 3} \sqrt{x^{2}+x+4}$
(iv) $\underline{\operatorname{Lim}}_{x \rightarrow 2} \sqrt{x^{2}+4}$
(v) $\underline{\operatorname{Lim}}_{x \rightarrow 2}\left(\sqrt{x^{2}+1}-\sqrt{x^{2}+5}\right)$
(vi) $\underline{\operatorname{Lim}}_{x \rightarrow-2} \frac{2 x^{3}+5 x}{3 x-2}$
3. Evaluate each limit by using algebraic techniques:
(i) $\quad \underline{\operatorname{Lim}}_{x \rightarrow-1} \frac{x^{3}-x}{x+1}$
(ii) $\underline{\operatorname{Lim}}_{x \rightarrow 3}\left(\frac{x^{2}-5 x+6}{x^{2}-2 x-3}\right)$
(iii) $\quad \underline{\operatorname{Lim}}_{x \rightarrow 2}\left(\frac{x^{3}-8}{x^{2}-5 x+6}\right)$
(iv) $\underline{\operatorname{Lim}}_{x \rightarrow 1} \frac{x^{2}-3 x^{2}+3 x-1}{x^{2}-x}$
(v) $\underline{\operatorname{Lim}}_{x \rightarrow 2}\left(\frac{x^{3}-6 x^{2}+12 x-8}{x^{3}-4 x}\right)$
(vi) $\underline{\operatorname{Lim}}_{x \rightarrow 1}\left(\frac{x^{4}-1}{x^{2}-3 x+2}\right)$
(vii) $\underline{\operatorname{Lim}}_{x \rightarrow 2} \frac{x-2}{\sqrt{x+2}-\sqrt{6-x}}$
(viii) $\underline{\operatorname{Lim}}_{h \rightarrow 0} \frac{\sqrt{x+h}-\sqrt{x}}{h}$
(ix) $\quad \underline{\operatorname{Lim}}_{x \rightarrow \infty} \frac{x^{n}-a^{n}}{x^{n}-a^{m}}$
4. Evaluate the following limits:
(i) $\quad \underline{\operatorname{Lim}}_{x \rightarrow 0} \frac{\sin 5 x}{x}$
(ii) $\quad \underline{\operatorname{Lim}}_{x \rightarrow 0} \frac{\sin x^{\prime \prime}}{x}$
(iii) $\underline{\operatorname{Lim}}_{0 \rightarrow 0} \frac{1-\cos \theta}{\sin \theta}$
(iv) $\underline{\operatorname{Lim}}_{x \rightarrow \frac{\pi}{4}} \frac{\sin x-\cos x}{x-\frac{\pi}{4}}$
(v) $\underline{\operatorname{Lim}}_{x \rightarrow 0} \frac{\cos a x-\cos b x}{x^{2}}$
(vi) $\underline{\operatorname{Lim}}_{x \rightarrow \frac{\pi}{4}} \frac{\tan x-1}{x-\frac{\pi}{4}}$
(vii) $\underline{\operatorname{Lim}}_{x \rightarrow 0} \frac{1-\cos 2 x}{x^{2}}$
(viii) $\underline{\operatorname{Lim}}_{x \rightarrow 0} \frac{\cos a x-\cos b x}{\cos c x-\cos d x}$
(ix) $\quad \underline{\operatorname{Lim}}_{x \rightarrow 1} \frac{x^{3}-1}{x^{2}-1}$
(x) $\quad \underline{\operatorname{Lim}}_{x \rightarrow 3} \frac{x^{2}-x \log x+3 \log x-9}{x-3}$
(xi) $\quad \underline{\operatorname{Lim}}_{x \rightarrow 0} \frac{x\left(2^{x}-1\right)}{1-\cos x}$
5. Express each limit in terms of $e$.
(i) $\quad \underline{\operatorname{Lim}}_{n \rightarrow+\infty}\left(1+\frac{1}{n}\right)^{2 n}$
(ii) $\quad \underline{\operatorname{Lim}}_{n \rightarrow+\infty}\left(1+\frac{1}{n}\right)^{n}$
(iii) $\underline{\operatorname{Lim}}_{n \rightarrow+\infty}\left(1-\frac{1}{n}\right)^{n}$
(iv) $\quad \underline{\operatorname{Lim}}_{n \rightarrow+\infty}\left(1+\frac{1}{3 n}\right)^{n}$
(v) $\quad \underline{\operatorname{Lim}}_{n \rightarrow+\infty}\left(1+\frac{4}{n}\right)^{n}$
(vi) $\underline{\operatorname{Lim}}_{x \rightarrow 0}(1+3 x)^{\frac{2}{x}}$
(vii) $\underline{\operatorname{Lim}}_{x \rightarrow 0}\left(1+2 x^{2}\right)^{\frac{1}{x^{2}}}$
(viii) $\underline{\operatorname{Lim}}_{x \rightarrow 0} \frac{e^{a x}-e^{b x}}{a b x}$
(ix) $\quad \underline{\operatorname{Lim}}_{x \rightarrow \infty}\left(\frac{x}{1+x}\right)^{x}$
(x) $\quad \underline{\operatorname{Lim}}_{x \rightarrow 0} \frac{\frac{1}{x}-1}{e^{\frac{1}{x}}+1}, x<0$
(xi) $\quad \underline{\operatorname{Lim}}_{x \rightarrow 0} \frac{e^{\frac{1}{x}}-1}{e^{x}+1}, x>0$
(xii) $\quad \underline{\operatorname{Lim}}_{x \rightarrow 2} \frac{e^{x}-e^{2}}{x-2}$

# 12.3 Continuity and Discontinuity of Functions 12.3.1 One-Sided Limits 

In defining $\operatorname{Lim}_{x \rightarrow c} f(x)$, we restricted $x$ in an open interval containing $c$ i.e., we studied the behaviour of $f$ on both sides of $c$. However, in some cases it is necessary to investigate one sided limits that is, the left hand limit and the right hand limit.

## (i) The Left Hand Limit

$\operatorname{Lim}_{x \rightarrow c^{\prime}} f(x)=L$ is read as the limit of $f(x)$ is equal to $L$ as $x$ approaches $c$ from the left i.e., for all $x$ sufficiently close to $c$, but less than $c$, the value of $f(x)$ can be made as close as we please to $L$.
(ii) The Right Hand Limit
$\operatorname{Lim}_{x \rightarrow c^{\prime}} f(x)=M$ is read as the limit of $f(x)$ is equal to $M$ as $x$ approaches $c$ from the right i.e., for all $x$ sufficiently close to $c$, but greater than $c$, the value of $f(x)$ can be made as close as we please to $M$.

### 12.3.2 Criterion for Existence of Limit of a Function

$$
\operatorname{Lim}_{x \rightarrow c} f(x)=L \text { if and only if } \operatorname{Lim}_{x \rightarrow c} f(x)=\operatorname{Lim}_{x \rightarrow c} f(x)=L
$$

Example 9 Determine whether $\operatorname{Lim}_{x \rightarrow 2} f(x)$ and $\operatorname{Lim}_{x \rightarrow 4} f(x)$ exist, when

$$
f(x)=\left\{\begin{array}{ll}
2 x+1 & \text { if } 0 \leq x \leq 2 \\
7-x & \text { if } 2<x<4 \\
x & \text { if } 4 \leq x \leq 6
\end{array}\right.
$$

Solution (i) $\quad \operatorname{Lim}_{x \rightarrow 2} f(x)=\operatorname{Lim}_{x \rightarrow 2}(2 x+1)=4+1=5$

$$
\begin{aligned}
& \operatorname{Lim}_{x \rightarrow 2^{\prime}} f(x)=\operatorname{Lim}_{x \rightarrow 2}(7-x)=7-2=5 \\
& \text { Since } \quad \operatorname{Lim}_{x \rightarrow 2} f(x)=\operatorname{Lim}_{x \rightarrow 2^{\prime}} f(x)=5 \\
& \Rightarrow \quad \operatorname{Lim}_{x \rightarrow 2} f(x) \text { exists and is equal to } 5 .
\end{aligned}
$$

[Image removed]
(ii) $\quad \operatorname{Lim}_{x \rightarrow 4^{\prime}} f(x)=\operatorname{Lim}_{x \rightarrow 4^{\prime}}(7-x)=7-4=3$

$$
\operatorname{Lim}_{x \rightarrow 4^{\prime}} f(x)=\operatorname{Lim}_{x \rightarrow 4^{\prime}}(x)=4
$$

Since $\operatorname{Lim}_{x \rightarrow 4^{\prime}} f(x) \neq \operatorname{Lim}_{x \rightarrow 4^{\prime}} f(x)$
Therefore, $\operatorname{Lim}_{x \rightarrow 4} f(x)$ does not exist.

# 12.3.3 Continuity of a Function at a Point 

## (a) Continuous Function

A function $f$ is said to be continuous at a number " $c$ " if and only if the following three conditions are satisfied.
(i) $f(c)$ is defined
(ii) $\operatorname{Lim}_{x \rightarrow c} f(x)$ exists
(iii) $\operatorname{Lim}_{x \rightarrow c} f(x)=f(c)$
(b) Discontinuous Function

If one or more of these three conditions fail to hold at " $c$ ", then the function $f$ is said to be discontinuous at " $c$ ".

Example 10 Consider the function $f(x)=\frac{x^{2}-1}{x-1}$, discuss the continuity of $f$ at $x=1$.
Solution Here $f(1)$ is not defined.
$\Rightarrow f(x)$ is discontinuous at 1 .
Example 11 For $f(x)=3 x^{2}-5 x+4$, discuss continuity of $f$ at $x=1$.
Solution $\operatorname{Lim}_{x \rightarrow 1} f(x)=\operatorname{Lim}_{x \rightarrow 1}\left(3 x^{2}-5 x+4\right)=3-5+4=2$ and $f(1)=3-5+4=2$

$$
\Rightarrow \quad \operatorname{Lim}_{x \rightarrow 1} f(x)=f(1)
$$

Therefore, $f(x)$ is continuous at $x=1$
Example 12 Discuss the continuity of the functions $f(x)$ and $g(x)$ at $x=3$
(a) $f(x)=\left\{\begin{array}{ll}\frac{x^{2}-9}{x-3} & \text { if } \quad x \neq 3 \\ 6 & \text { if } \quad x=3\end{array}\right.$
(b) $g(x)=\left\{\frac{x^{2}-9}{x-3} \quad \text { if } \quad x \neq 3\right.$

Solution (a) $f(3)=6$
Now, $\operatorname{Lim}_{x \rightarrow 3} f(x)=\operatorname{Lim}_{x \rightarrow 3} \frac{x^{2}-9}{x-3}$

$$
\begin{aligned}
& =\operatorname{Lim}_{x \rightarrow 3} \frac{(x+3)(x-3)}{(x-3)} \\
& =\operatorname{Lim}_{x \rightarrow 3}(x+3)=3+3=6
\end{aligned}
$$

As $\quad \operatorname{Lim}_{x \rightarrow 3} f(x)=6=f(3)$
$f(x)$ is continuous at $x=3$. It is noted that there is no break in the graph.
[Image removed]

Figure 12.5

(b) $g(x)=\frac{x^{2}-9}{x-3}$ if $x \neq 3$

As $g(x)$ is not defined at $x=3$
$\Rightarrow g(x)$ is discontinuous at $x=3$
It is noted that there is a break in the graph at $x=3$ near $x=3$ as shown in the Figure 12.6.
Example 13 Discuss continuity of $f(x)$ at $x=3$, when

$$
f(x)= \begin{cases}x-1, & \text { if } \quad x<3 \\ 2 x+1, & \text { if } \quad x \geq 3\end{cases}
$$

[Image removed]

Solution A sketch of the graph of $f$ is shown in the Figure 12.7. We can see that there is a break in the graph at a point when $x=3$.

Now $f(3)=2(3)+1=7$
$\Rightarrow$ Condition (i) is satisfied.
$\operatorname{Lim}_{x \rightarrow 3} f(x)=\operatorname{Lim}_{x \rightarrow 3}(x-1)=3-1=2$
$\operatorname{Lim}_{x \rightarrow 3} f(x)=\operatorname{Lim}_{x \rightarrow 3}(2 x+1)=6+1=7$
$\operatorname{Lim}_{x \rightarrow 3} f(x) \neq \operatorname{Lim}_{x \rightarrow 3} f(x)$
i.e., condition (ii) is not satisfied.
$\therefore \quad \operatorname{Lim}_{x \rightarrow 3} f(x)$ does not exist.
Hence, $f(x)$ is not continuous at $x=3$
[Image removed]

Figure 12.7

# EXERCISE 12.2 

1. Determine the left hand limit and the right hand limit and then, find limit of the following functions when $x \rightarrow c$.
(i) $f(x)=2 x^{2}+x-5, c=1$
(ii) $f(x)=\frac{x^{2}-9}{x-3}, c=-3$
(iii) $f(x)=|x-5|, c=5$
2. Discuss the continuity of $f(x)$ at $x=c$
(i) $f(x)= \begin{cases}2 x+5 & \text { if } x \leq 2 \\ 4 x+1 & \text { if } x>2\end{cases}, c=2$
(ii) $f(x)= \begin{cases}3 x-1 & \text { if } x<1 \\ 4 & \text { if } x=1, c=1 \\ 2 x & \text { if } x>1\end{cases}$
3. If $f(x)= \begin{cases}3 x & \text { if } \quad x \leq-2 \\ x^{2}-1 & \text { if } \quad-2<x<2 \text { Discuss continuity at } x=2 \text { and } x=-2 \\ 3 & \text { if } x \geq 2\end{cases}$

4. If $f(x)=\left\{\begin{array}{cc}x+2 & x \leq-1 \\ c+2 & x>-1\end{array}\right.$
find " $c$ " so that $\operatorname{Lim}_{x \rightarrow-1} f(x)$ exists.
5. Find the values of $m$ and $n$, so that given function $f$ is continuous at $x=3$
(i) $f(x)=\left\{\begin{array}{cll}mx & \text { if } x<3 \\ n & \text { if } x=3 & \text { (ii) } f(x)=\{ \\ -2 x+9 & \text { if } & x>3\end{array}\right.$
(ii) $f(x)=\left\{\begin{array}{lll}mx & \text { if } x<3 \\ x^{2} & \text { if } x \geq 3\end{array}\right.$
6. $f(x)=\left\{\begin{array}{cll}\sqrt{2 x+5}-\sqrt{x+7} & , & x \neq 2 \\ k & , & x=2\end{array}\right.$

Find value of $k$ so that $f$ is continuous $x=2$.
7. Given the function $f(x)=\left\{\begin{array}{cc}2 x+3, & x \leq 1 \\ -x+4, & x>1\end{array}\right.$

Discuss the limit and continuity at $x=1$.

# 12.4 Application of Transcendental Functions to Limits and Continuity on Real World Problems 

Limit and continuity of transcendental functions are fundamental concepts in calculus with numerous real-world applications.
These concepts help us model, analyze and solve problems in various fields such as growth and decay, finance, economics, surveying and predicting long-term stock prices.

## Example 14 Growth and Decay (Radioactive Decay)

The radioactive decay of a substance is given by the function $A(t)=A_{0} e^{-k t}$, where $A_{0}$ is the initial amount of the substance, $k$ is the decay constant, and $t$ is the time in years. Find the limit of the amount of substance as $t \rightarrow \infty$.

## Solution

We need to compute the limit: $\operatorname{Lim}_{t \rightarrow \infty} A(t)=\operatorname{Lim}_{t \rightarrow \infty} A_{0} e^{-k t}$
As $t \rightarrow \infty, e^{-k t} \rightarrow 0$, so $\operatorname{Lim}_{t \rightarrow \infty} A_{0} e^{-k t}=A_{0} \times 0=0$
Thus, the amount of radioactive substance approaches 0 as time increases indefinitely. Example 15 Finance (Compound Interest)
The value of an investment grows according to the formula for continuous compounding $A(t)=P_{0} e^{r t}$, where $P_{0}$ is the initial principal, $r$ is the annual interest rate, and $t$ is the time in years. What happens to the value of the investment as $t \rightarrow \infty$ ?

# Unit 42 Limit of Sequences and Conthority 

Solution We need to compute the limit: $\operatorname{Lim}_{t \rightarrow \infty} A(t)=\operatorname{Lim}_{t \rightarrow \infty} P_{0} e^{r t}$
Since $e^{r t} \rightarrow \infty$ as $t \rightarrow \infty$ for any positive $r$, the value of the investment grows without bound:

$$
\operatorname{Lim}_{t \rightarrow \infty} P_{0} e^{r t}=\infty
$$

Thus, the value of the investment increases indefinitely as time approaches infinity.

## Example16 Economics (Supply and Demand)

In economics, the demand function $D(p)$ decreases as the price $p$ increases. Suppose the demand function is given by $D(p)=\frac{100}{p+1}$, where $p$ is the price in dollars. Find the limit of the demand as the price becomes very large, i.e., $\operatorname{Lim}_{p \rightarrow \infty} D(p)$ :

Solution $\operatorname{Lim}_{p \rightarrow \infty} D(p)=\operatorname{Lim}_{p \rightarrow \infty} \frac{100}{p+1}$
As $p \rightarrow \infty$, the denominator becomes very large, so $\operatorname{Lim}_{p \rightarrow \infty} \frac{100}{p+1}=0$
Thus, as the price becomes very large, the demand approaches 0 .

## Example17 Astronomy

The apparent brightness $B(d)$ of a star decreases as the distance from Earth increases following the inverse square law $B(d)=\frac{L}{d^{2}}$, where $L$ is the star's luminosity. Find the limit of the brightness as $d \rightarrow \infty$.

Solution $\quad \operatorname{Lim}_{d \rightarrow \infty} B(d)=\operatorname{Lim}_{d \rightarrow \infty} \frac{L}{d^{2}}$
As $d \rightarrow \infty$ the denominator becomes very large, so:

$$
\operatorname{Lim}_{d \rightarrow \infty} \frac{L}{d^{2}}=0
$$

Thus, as the distance increases indefinitely, the apparent brightness of the star approaches 0 .

## EXERCISE 12.3

1. A substance decays exponentially following the formula $A(t)=A_{0} e^{-0.1 t}$, where $A_{0}$ is the initial amount. Find the limit of $A(t)$ as $t \rightarrow \infty$.
2. A town's population is modeled by $P(t)=\frac{100,000}{1+9 e^{-0.5 t}}$. What is the long-term population as $t \rightarrow \infty$.

3. A company's weekly sales (in thousands) follow the function $S(t)=\frac{500 t}{t+10}$. What is the limit of $S(t)$ as $t \rightarrow \infty$ and what does it represent?
4. Signal strength $S(d)$ at a distance $d$ from a tower is modeled as $S(d)=\frac{1000}{d^{2}}$.
(i) What is the signal strength at $d=10$ ?
(ii) What happens to signal strength as $d \rightarrow \infty$ ?
5. A stock price grows according to the function $P(t)=50 \mathrm{e}^{0.05 t}$.
(i) Find the limit of $P(t)$ as $t \rightarrow \infty$.
(ii) Calculate the price after 10 years.
6. The factory's cost function is given as:

$$
C(x)= \begin{cases}10 x+500 & \text { if } \quad x \leq 100 \\ 12 x+300 & \text { if } \quad x>100\end{cases}
$$

Is the cost function continuous at $x=100$ ?
7. Inflation is modeled by $I(t)=I_{0} e^{0.05 t}$, where $I_{0}$ is the initial price index and $t$ is the number of years
(i) Find the inflation rate after 5 years if $I_{0}=100$.
(ii) What is the expected price index after 10 years?
8. The cost to produce $x$ units is:

$$
C(x)= \begin{cases}5 x+20 & \text { if } \quad x \leq 10 \\ 6 x+10 & \text { if } \quad x>10\end{cases}
$$

Is the cost function continuous at $x=10$ ?

# Differentiation 

## INTRODUCTION

The ancient Greeks knew the concepts of area, volume, centroids etc. which are related to integral calculus. Later on, in the seventeenth century, Sir Isaac Newton, an English mathematician ( 1642 - 1727) and Gottfried Whilhe G. W. Leibniz, a German mathematician, ( 1646 - 1716) considered the problem of instantaneous rates of change. They reached independently to the invention of differential calculus. After the development of calculus, mathematics became a powerful tool for dealing with rates of change and describing the physical universe.

### 13.1 Tangent to a Curve at a Point

Let $P(x, f(x))$ and $Q(x+\delta x, f(x+\delta x))$ be two points on arc $A B$ of graph of $f$ defined by the equation $y=f(x)$ as shown in Figure 13.1.
Where $\delta x$ is the increment in the value of $x$ (read as delta $x$ )
The line $P Q$ is secant of the curve and slope of
[Image removed]

Figure 13.1
secant line passing through $P(x, f(x))$ and $Q(x+\delta x, f(x+\delta x))$ is:

$$
m_{\mathrm{am}}=\frac{R Q}{P R}=\frac{f(x+\delta x)-f(x)}{\delta x}
$$

Where $m_{\text {anc }}$ is slope of the secant line. Revolving the secant line $P Q$ towards $P$, some of its successive positions $P Q_{1}, P Q_{2}, P Q_{3}, \ldots$ are shown in the Figure 13.2. Points $Q_{i}(i=1,2,3, \ldots)$ are getting closer and closer to the point $P$ and $P R$ are approaching zero.
[Image removed]

Figure 13.2

In other words, as $\delta x \rightarrow 0$, the point $Q$ approaches $P$, and the secant line becomes the tangent line. The revolving secant line becomes the tangent line $P T$ at $P$ while $\delta x$

approaches zero, that is,

$$
m_{\mathrm{ten}}=\operatorname{Lim}_{\delta x \rightarrow 0} \frac{f(x+\delta x)-f(x)}{\delta x}
$$

where $m_{\text {ten }}$ denotes the slope of tangent line. We see that $m_{\text {ten }}$ is the limit of $m_{\text {ten }}$ as $Q$ approaches $P$ along the curve $y=f(x)$.
Example 1 Find the gradient and an equation of tangent line to the graph of $f(x)=x^{2}-2$ at the point $P(-1,-1)$.
Solution To find the gradient or slope of the tangent line at point $(-1,-1)$, put $x=-1$ in equation (2)

$$
\begin{aligned}
m_{\text {ten }} & =\lim _{\delta x \rightarrow 0} \frac{f(-1+\delta x)-f(-1)}{\delta x} \\
& =\operatorname{Lim}_{\delta x \rightarrow 0} \frac{(-1+\delta x)^{2}-2-\left((-1)^{2}-2\right)}{\delta x} \\
& =\operatorname{Lim}_{\delta x \rightarrow 0} \frac{1-2 \delta x+\delta x^{2}-2-(1-2)}{\delta x} \\
& =\operatorname{Lim}_{\delta x \rightarrow 0} \frac{1-2 \delta x+\delta x^{2}-2+1}{\delta x}=\operatorname{Lim}_{\delta x \rightarrow 0} \frac{-2 \delta x+\delta x^{2}}{\delta x} \\
& =\operatorname{Lim}_{\delta x \rightarrow 0} \frac{\delta x(-2+\delta x)}{\delta x}=\operatorname{Lim}_{\delta x \rightarrow 0}(-2+\delta x)=-2
\end{aligned}
$$

[Image removed]

Now to find the equation of tangent line we use the point slope form of equation of line with slope $=-2$ and point $(-1,-1)$
$y-(-1)=-2(x-(-1)) \Rightarrow y+1=-2 x-2$
or $y=-2 x-3$, which is the required equation of tangent line.
The graph of $f$ and tangent line are shown in the above figure.

# 13.2 Derivative as the Limit of a Difference Quotient 

Let $f$ be a real valued function continuous in the interval $\left(x, x_{1}\right) \subseteq D_{f}$ (domain of $f$ ), then difference quotient $\frac{f\left(x_{1}\right)-f(x)}{x_{1}-x}$
represents the average rate of change in the value of $f$ with respect to the change $x_{1}-x$ in the value of independent variable $x$.

If $x_{1}$ approaches to $x$, then $\operatorname{Lim}_{x_{1} \rightarrow x} \frac{f\left(x_{1}\right)-f(x)}{x_{1}-x}$
provided this limit exists, is called the instantaneous rate of change of $f$ with respect to $x$ and is written as $f^{\prime}(x)$.
If $x_{1}=x+\delta x$ i.e., $x_{1}-x=\delta x$, then the expression (i) can be expressed as

$$
\frac{f(x+\delta x)-f(x)}{\delta x}
$$

and

$$
\operatorname{Lim}_{x_{x} \rightarrow 0} \frac{f(x+\delta x)-f(x)}{\delta x}
$$

provided the limit exist, is defined to be the derivative of $f$ (or differential coefficient of $f$ ) with respect to $x$ and is denoted by $f^{\prime}(x)$ (read as " $f$-prime of $x^{\prime \prime}$ ). The domain of $f^{\prime}$ consists of all $x$ for which the limit exists. If $x \in D_{f}$ and $f^{\prime}(x)$ exists, then $f$ is said to be differentiable at $x$. The process of finding $f^{\prime}$ is called differentiation.

# 13.2.1 Derivative as the Rate of Change of Velocity 

The rate of change is a fundamental concept in describing the motion of an object moving in a straight line. In physics, this is typically analyzed using position, velocity, and acceleration, which are all related through derivatives (rates of change).
The position versus time graph provides a simple interpretation of the average velocity over a given time interval.
Suppose a particle moves in a straight line and its position at time $t$ is given by the function $s(t)$. The average velocity over the interval from $t$ to $t_{1}$ denoted by $v_{\text {avg }}$ is defined as:

$$
v_{\text {ang }}=\frac{s\left(t_{1}\right)-s(t)}{t_{1}-t}
$$

Equation (i) also represents the slope of secant line passing through the points $(t, s(t))$ and $\left(t_{1}, s\left(t_{1}\right)\right)$. If the interval $t_{1}-t$ is not small, this average velocity does not accurately represent the rate of change at time $t$.
To illustrate this, consider a particle whose position at time $t$ (in seconds) is given by a function $s(t)=t^{2}+t$ in metres. The average rate of change over various time intervals

Starting at $t=3$ seconds is shown in the table below:

| Interval | $t=3$ secs to $t=5$ secs | $t=3$ secs to $t=4$ secs | $t=3$ secs to $t=3.5$ secs |
| :--: | :--: | :--: | :--: |
| Average velocity | $\begin{gathered} s(5)-s(3) \\ 5-3 \end{gathered}=\frac{30-12}{2}=9$ | $\begin{gathered} s(4)-s(3) \\ 4-3 \end{gathered}=\frac{20-12}{1}=8$ | $\begin{gathered} s(3.5)-s(3) \\ 3.5-3 \end{gathered}=\frac{63}{4}-12$ $0.5=7.5$ |
| [Image removed] | $\begin{gathered} 50 \\ 40 \\ 30 \\ 20 \\ 10 \end{gathered}$ | $\begin{gathered} 50 \\ 40 \\ 30 \\ 20 \\ 10 \end{gathered}$ | $\begin{gathered} 50 \\ 40 \\ 30 \\ 20 \\ 10 \end{gathered}$ |

We observe that these values are not closely approximate the particle's velocity at exactly 3 seconds. To obtain a better approximation of velocity at $x=3$, we use smaller intervals:

| Interval | Average velocity |
| :-- | :-- |
| $t=3$ secs to $t=3.1$ secs | $\begin{gathered} \frac{((3.1)^{2}+3.1)-12}{3.1-3}=\frac{0.71}{0.1}=7.1 \\ \hline \end{gathered}$ |
| $t=3$ secs to $t=3.01$ secs | $\begin{gathered} \frac{((3.01)^{2}+3.01)-12}{3.01-3}=\frac{0.0701}{0.01}=7.01 \\ \hline \end{gathered}$ |
| $t=3$ secs to $t=3.001$ secs | $\begin{gathered} \frac{((3.001)^{2}+3.001)-12}{3.001-3}=\frac{0.007001}{0.001}=7.001 \end{gathered}$ |

We see as the length of the time interval decreases, the average velocity becomes instantaneous velocity at $t=3$. Based on the trend, we estimate the instantaneous velocity to be approximately $7 \mathrm{~m} / \mathrm{sec}$.
Thus, over a sufficiently small interval, the velocity changes negligibly. If $t_{1}$ is very close to $t$, the average velocity over $t_{1}-t$ approximates the instantaneous velocity at $t$. As $t_{1}$ approaches $t$, the average velocity is called the instantaneous velocity.
This is similar to approximating the slope of a tangent line by calculating the slope of a secant line. Mathematically, the instantaneous velocity denoted by $v_{\text {inst }}$ is given by the following limit:

$$
v_{\text {inst }}=\operatorname{Lim}_{t_{1} \rightarrow t} \frac{s\left(t_{1}\right)-s(t)}{t_{1}-t} \quad \text { (Provide the limit exist) }
$$

For convenient, if $t_{1}=t+\delta t$, then as $t_{1} \rightarrow t \Rightarrow \delta t \rightarrow 0$, thus above equation becomes:

$$
v_{\text {inst }}=\operatorname{Lim}_{t_{t} \rightarrow 0} \frac{s(t+\delta t)-s(t)}{\delta t}
$$

In other words, the instantaneous velocity is the derivative of the position function $s(t)$ with respect to time.
Example 2 A particle moves along a line such that its position after $t$ hours is given by: $s(t)=4 t^{2}+2 t+1$ (in miles)
(a) Find the average velocity over the interval $[2,5]$
(b) Find the instantaneous velocity at $t=3$

Solution (a) given position function $s(t)=4 t^{2}+2 t+1$, where $2 \leq t \leq 5$
The average velocity over the interval $2 \leq t \leq 5$ is:

$$
\begin{aligned}
\text { Average velocity }=v_{\text {avg }} & =\frac{s(5)-s(2)}{5-2}=\frac{4(5)^{2}+2(5)+1-[4(2)^{2}+2(2)+1]}{3} \\
& =\frac{111-21}{3}=\frac{90}{3}=30 \mathrm{miles} / \mathrm{hours}
\end{aligned}
$$

(b) Instantaneous velocity can be found using the formula

$$
\begin{aligned}
& \text { Instantaneous velocity }=\lim _{\delta t \rightarrow 0} \frac{s(t+\delta t)-s(t)}{\delta t} \\
& =\lim _{\delta t \rightarrow 0} \frac{4(3+\delta t)^{2}+2(3+\delta t)+1-[4(3)^{2}+2(3)+1]}{\delta t} \\
& =\lim _{\delta t \rightarrow 0} \frac{4\left(9+6 \delta t+\delta t^{2}\right)+6+2 \delta t+1-43}{\delta t} \\
& =\lim _{\delta t \rightarrow 0} \frac{36+24 \delta t+4 \delta t^{2}+6+2 \delta t+1-43}{\delta t} \\
& =\lim _{\delta t \rightarrow 0} \frac{43+26 \delta t+4 \delta t^{2}-43}{\delta t}=\lim _{\delta t \rightarrow 0} \frac{26 \delta t+4 \delta t^{2}}{\delta t}
\end{aligned}
$$

$$
=\lim _{\delta t \rightarrow 0} \frac{\delta t(26+4 \delta t)}{\delta t}=\operatorname{Lim}_{t t \rightarrow 0}(26+4 \delta t)=26
$$

Thus, instantaneous velocity at $t=3$ is 26 miles/hour

# 13.3 Process of Finding Derivative $f^{\prime}(x)$ by Definition 

### 12.3.1 Notation of Derivative

Several notations are used for derivatives. We have used the functional symbol $f^{\prime}(x)$, for the derivative of $f$ at $x$. For the function $y=f(x)$.

$$
y+\delta y=f(x+\delta x)
$$

Dividing both the sides of (iv) by $\delta x$, we get

$$
\frac{\delta y}{\delta x}=\frac{f(x+\delta x)-f(x)}{\delta x}
$$

Taking limit of both the sides of (v) as $\delta x \rightarrow 0$, we have

$$
\begin{aligned}
& \lim _{\delta x \rightarrow 0} \frac{\delta y}{\delta x}=\lim _{\delta x \rightarrow 0} \frac{f(x+\delta x)-f(x)}{\delta x} \\
& \lim _{\delta x \rightarrow 0} \frac{\delta y}{\delta x} \text { is denoted by } \frac{d y}{d x}, \text { so (vi) is written as } \frac{d y}{d x}=f^{\prime}(x)
\end{aligned}
$$

# Note 

The symbol $\frac{d y}{d x}$ is used for the derivative of $y$ with respect to $x$ and here it is not a quotient of $d y$ and $d x . \frac{d y}{d x}$ is also denoted by $y^{\prime}$.

Now we write, in a table the notations for derivative of $y=f(x)$ used by different mathematicians:

| Name of mathematician | Leibniz | Newton | Lagrange | Euler |
| :--: | :--: | :--: | :--: | :--: |
| Notation used for derivative | $\frac{d y}{d x}$ or $\frac{d f}{d x}$ | $f^{\prime \prime}(x)$ or $y^{\prime \prime}$ | $f^{\prime}(x)$ | $D f(x)$ |

If we replace $x+\delta x$ by $x$ and $x$ by $a$, then the expression $f(x+\delta x)-f(x)$ becomes $f(x)-f(a)$ and the change $\delta x$ in the independent variable, in this case, is $x-a$.
So, the expression $\frac{f(x+\delta x)-f(x)}{\delta x}$ is written as $\frac{f(x)-f(a)}{x-a}$
Taking the limit of the expression (vii) when $x \rightarrow a$, gives $\operatorname{Lim}_{x \rightarrow a} \frac{f(x)-f(a)}{x-a}=f^{\prime}(a)$.
Here $f^{\prime}(a)$ is called the derivative or gradient of $f$ at $x=a$.

### 13.3.2 Finding $f^{\prime}(x)$ by Definition of Derivative

Given a function $f$, then $f^{\prime}(x)$ if it exists, can be found by the following four steps:
Step I: Find $f(x+\delta x)$
Step II: Simplify $f(x+\delta x)-f(x)$
Step III: Divide $f(x+\delta x)-f(x)$ by $\delta x$ to get $\frac{f(x+\delta x)-f(x)}{\delta x}$ and simplify it.
Step IV: Find $\operatorname{Lim}_{\delta x \rightarrow 0} \frac{f(x+\delta x)-f(x)}{\delta x}$
The method of finding derivatives by this process is called differentiation by definition or by ab-initio or from first principle.

Example 3 Find the derivative of the following functions by definition
(a) $f(x)=c$
(b) $f(x)=x^{2}$

Solution
(a) $f(x)=c$
(i) $f(x+\delta x)=c$
(ii) $f(x+\delta x)-f(x)=c-c=0$
(iii) $\frac{f(x+\delta x)-f(x)}{\delta x}=\frac{0}{\delta x}=0$
(iv) $\operatorname{Lim}_{k \rightarrow 0} \frac{f(x+\delta x)-f(x)}{\delta x}=\operatorname{Lim}_{k \rightarrow-0}(0)=0$

Thus, $f^{\prime}(x)=0$, that is, $\frac{d}{d x}(c)=0$
(b) $f(x)=x^{2}$
(i) $f(x+\delta x)=(x+\delta x)^{2}$
(ii) $f(x+\delta x)-f(x)=(x+\delta x)^{2}-x^{2}=x^{2}+2 x \delta x+(\delta x)^{2}-x^{2}=(2 x+\delta x) \delta x$
(iii) $\frac{f(x+\delta x)-f(x)}{\delta x}=\frac{(2 x+\delta x) \delta x}{\delta x}=2 x+\delta x ;(\delta x \neq 0)$
(iv) $\operatorname{Lim}_{k \rightarrow 0} \frac{f(x+\delta x)-f(x)}{\delta x}=\operatorname{Lim}_{k \rightarrow 0}(2 x+\delta x)=2 x$
i.e., $\quad f^{\prime}(x)=2 x$

Example 4 Find the derivative of $\sqrt{x}$ at $x=a$ from first principle.
Solution If $f(x)=\sqrt{x}$, then
(i) $f(x+\delta x)=\sqrt{x+\delta x}$ and
(ii) $f(x+\delta x)-f(x)=\sqrt{x+\delta x}-\sqrt{x}$

$$
=\frac{(\sqrt{x+\delta x}-\sqrt{x})(\sqrt{x+\delta x}+\sqrt{x})}{\sqrt{x+\delta x}+\sqrt{x}} \quad \text { (rationalizing the } \text { numerator })
$$

$$
=\frac{x+\delta x-x}{\sqrt{x+\delta x}+\sqrt{x}}
$$

i.e., $f(x+\delta x)-f(x)=\frac{\delta x}{\sqrt{x+\delta x}+\sqrt{x}}$
(iii) Dividing both sides of (1) by $\delta x$, we have

$$
\begin{aligned}
\frac{f(x+\delta x)-f(x)}{\delta x} & =\frac{\delta x}{\delta x(\sqrt{x+\delta x}+\sqrt{x})} \\
& =\frac{1}{\sqrt{x+\delta x}+\sqrt{x}},(\delta x \neq 0)
\end{aligned}
$$

(iv) Taking limit of both the sides as $\delta x \rightarrow 0$, we have

$$
\lim _{\delta x \rightarrow 0} \frac{f(x+\delta x)-f(x)}{\delta x}=\operatorname{Lim}_{\delta x \rightarrow 0}\left(\frac{1}{\sqrt{x+\delta x}+\sqrt{x}}\right)
$$

i.e., $\quad f^{\prime}(x)=\frac{1}{\sqrt{x}+\sqrt{x}}=\frac{1}{2 \sqrt{x}},(x>0)$ and $f^{\prime}(a)=\frac{1}{2 \sqrt{a}}$

Alternate method: Putting $x=a$ in $f(x)=\sqrt{x}$, gives $f(a)=\sqrt{a}$

$$
\text { So, } \quad f(x)-f(a)=\sqrt{x}-\sqrt{a}
$$

Using alternative form for the definition of the derivative, we have

$$
\begin{aligned}
\frac{f(x)-f(a)}{x-a} & =\frac{\sqrt{x}-\sqrt{a}}{x-a} \\
& =\frac{(\sqrt{x}-\sqrt{a})(\sqrt{x}+\sqrt{a})}{(x-a)(\sqrt{x}+\sqrt{a})} \quad \text { (rationalizing the numerator) } \\
& =\frac{x-a}{(x-a)(\sqrt{x}+\sqrt{a})}=\frac{1}{\sqrt{x}+\sqrt{a}},(x \neq a)
\end{aligned}
$$

Taking limit of both the sides of (2) as $x \rightarrow a$, gives

$$
\lim _{x \rightarrow \infty} \frac{f(x)-f(a)}{x-a}=\operatorname{Lim}_{x \rightarrow a} \frac{1}{\sqrt{x}+\sqrt{a}}=\frac{1}{\sqrt{a}+\sqrt{a}}
$$

i.e.,

$$
f^{\prime}(a)=\frac{1}{2 \sqrt{a}}
$$

which is the gradient of $f$ at $x=a$.
Example 5 If $y=\frac{1}{x^{2}}$, then find $\frac{d y}{d x}$ at $x=-1$ by ab-initio method.
Solution Here, $y=\frac{1}{x^{2}}$, so

$$
y+\delta y=\frac{1}{(x+\delta y)^{2}}
$$

Subtracting (i) from (ii), we get

$$
\begin{aligned}
\delta y & =\frac{1}{(x+\delta x)^{2}}-\frac{1}{x^{2}}=\frac{x^{2}-(x+\delta x)^{2}}{x^{2}(x+\delta x)^{2}} \\
& =\frac{\{x+(x+\delta x)\}\{x-(x+\delta x)\}}{x^{2}(x+\delta x)^{2}}
\end{aligned}
$$

$$
=\frac{(2 x+\delta x)(-\delta x)}{x^{2}(x+\delta x)^{2}}=\frac{-\delta x(2 x+\delta x)}{x^{2}(x+\delta x)^{2}}
$$

Dividing both sides of (iii) by $\delta x$, we have

$$
\frac{\delta y}{\delta x}=\frac{-\delta x(2 x+\delta x)}{x^{2}(x+\delta x)^{2} \cdot \delta x}=\frac{-(2 x+\delta x)}{x^{2}(x+\delta x)^{2}}, \quad(\delta x \neq 0)
$$

Taking limit as $\delta x \rightarrow 0$, gives

$$
\begin{aligned}
\lim _{\delta x \rightarrow 0} \frac{\delta y}{\delta x} & =\lim _{\delta x \rightarrow 0} \frac{-(2 x+\delta x)}{x^{2}(x+\delta x)^{2}} \\
& =\frac{-(2 x)}{x^{2}\left(x^{2}\right)} \quad \text { (Using quotient theorem of limits) }
\end{aligned}
$$

i.e., $\frac{d y}{d x}=\frac{-2}{x^{3}}$ and $\left.\frac{d y}{d x}\right|_{x=-1}=\frac{-2}{(-1)^{3}}=\frac{-2}{-1}=2$

# 13.4 Derivation of $x^{n}$ where $n \in Z$ 

(a) We find the derivative of $x^{n}$ when $n$ is positive integer.
(b) Let $y=x^{n}$. Then

$$
y+\delta y=(x+\delta y)^{n}
$$

and $\quad \delta y=(x+\delta x)^{n}-x^{n}$
Using the binomial theorem, we have

$$
\begin{aligned}
& \delta y=\left[x^{n}+n x^{n-1} \cdot \delta x+\frac{n(n-1)}{2!} x^{n-2}(\delta x)^{2}+\cdots+(\delta x)^{n}\right]-x^{n} \\
& \text { i.e., } \quad \delta y=\delta x\left[n x^{n-1}+\frac{n(n-1)}{2!} x^{n-2} \cdot \delta x+\cdots+(\delta x)^{n-1}\right]
\end{aligned}
$$

Dividing both sides of (i) by $\delta x$, gives

$$
\frac{\delta y}{\delta x}=n x^{n-1}+\frac{n(n-1)}{2!} x^{n-2} \cdot \delta x+\cdots+(\delta x)^{n-1}
$$

Note that each term on the right hand side of (ii) involves $\delta x$ except the first term, so taking the limit as $\delta x \rightarrow 0$, we get $\frac{d y}{d x}=n x^{n-1}$

$$
\text { As } y=x^{n} \text {, so } \frac{d}{d x}\left(x^{n}\right)=n \cdot x^{n-1}
$$

(b) Let $y=x^{n}$ where $n$ is negative integer.

Let $n=-m$ ( $m$ is a positive integer). Then

$$
\begin{aligned}
y=x^{-m} & =\frac{1}{x^{m}} \\
\text { and } y+\delta y & =\frac{1}{(x+\delta x)^{m}}
\end{aligned}
$$

Subtracting (i) from (ii), gives

$$
\begin{aligned}
\delta y & =\frac{1}{(x+\delta x)^{m}}-\frac{1}{x^{m}}=\frac{x^{m}-(x+\delta x)^{m}}{x^{m}(x+\delta x)^{m}} \\
& =\frac{x^{m}-\left[x^{m}+m x^{m-1} \delta x+\frac{m(m-1)}{2!} x^{m-2}(\delta x)^{2}+\ldots \pm(\delta x)^{m}\right]}{x^{m}(x+\delta x)^{m}}
\end{aligned}
$$

(expanding $(x+\delta x)^{m}$ by binomial theorem)

$$
=-\delta x \frac{\left(m x^{m-1}+\frac{m(m-1)}{2!} x^{m-2} \delta x+\cdots+(\delta x)^{m-1}\right)}{x^{m}(x+\delta x)^{m}}
$$

and

$$
\frac{\delta y}{\delta x}=\frac{-1}{x^{m}(x+\delta x)^{m}} \cdot\left(m x^{m-1}+\frac{m(m-1)}{2!} x^{m-2} \cdot \delta x+\cdots+(\delta x)^{m-1}\right)
$$

Taking limit when $\delta x \rightarrow 0$, we get

$$
\begin{aligned}
& \frac{d y}{d x}=\frac{-1}{x^{m} \cdot x^{m}} \cdot m x^{m-1} \text { (all terms contaning } \delta x \text { vanish) } \\
& =-m x^{m-1} \cdot x^{-2 m} \\
& =-m x^{(-m)-1} \\
& \frac{d x}{d x}=n x^{n-1} \quad[\because-m=n] \\
& \text { or } \quad \frac{d(x)}{d x}=n x^{n-1}
\end{aligned}
$$

So, we have proved that $\frac{d}{d x}\left(x^{n}\right)=n x^{n-1}$, if $n \in Z$
The above rule also holds if $n \in Q-Z$, i.e. for rational powers.
For example, $\frac{d}{d x}\left(x^{\frac{2}{3}}\right)=\frac{2}{3} x^{\frac{2}{3}-1}=\frac{2}{3 x^{\frac{1}{3}}}$
The proof of $\frac{d}{d x}\left(x^{n}\right)=n x^{n-1}$ when $n \in Q-Z$ is left as an exercise.

# 13.5 Connection Between Derivatives and Continuity 

Calculus is a powerful branch of mathematics that allows us to study change and motion. Two of its foundational concepts of continuity and derivatives are deeply connected. While each concept has its own definition and application, understanding how they relate to each other is essential for solving real-world problems in mathematics.
As discussed in previous units, a function is continuous at a point if its graph has no breaks, jumps, or holes at that point. On the other hand, the derivative of a function at a point measures the instantaneous rate of change or equivalently, the slope of the tangent line at that point. However, this definition depends on the function being wellbehaved around the point. This leads to a well-known result:
If a function is differentiable at a point, it must also be continuous there. This means that differentiability implies continuity, but the reverse is not necessarily true. For example, consider the function $f(x)=|x|$, clearly this function is continuous at $x=0$ (see Figure 13.3). Now we check the differentiability of $f(x)=|x|$ at $x=0$.

$$
\begin{aligned}
f(x) & =|x| \\
f(0) & =|0|=0 \text { and } \\
f(0+\delta x) & =|0+\delta x|=|\delta x| \\
f(0+\delta x)-f(0) & =|\delta x|-0 \\
f(0+\delta x)-f(0) & =|\delta x| \\
& =\frac{|\delta x|}{\delta x}
\end{aligned}
$$

so

$$
f^{\prime}(x)=\lim _{\delta x \rightarrow 0} \frac{\delta x}{\delta x}
$$

Thus $f^{\prime}(x)=\lim _{\delta x \rightarrow 0} \frac{\delta x}{\delta x}$
Because $|\delta x|=\delta x$ when $\delta x>0$
and $|\delta x|=-\delta x$ when $\delta x<0$,
[Image removed]

Figure 13.3
so, we consider one-sided limits
$\operatorname{Lim}_{\delta x \rightarrow 0} \frac{|\delta x|}{\delta x}=\operatorname{Lim}_{\delta x \rightarrow 0} \frac{\delta x}{\delta x}=1$ and $\operatorname{Lim}_{\delta x \rightarrow 0} \frac{|\delta x|}{\delta x}=\operatorname{Lim}_{\delta x \rightarrow 0} \frac{-\delta x}{\delta x}=-1$
The right hand and left hand limits are not equal, therefore, the $\operatorname{Lim}_{\delta x \rightarrow 0} \frac{\delta x}{\delta x}$ does not exist. This implies that derivative of $f$ at $x=0$ does not exist, and thus, there is no tangent line to the graph of $f$ at this point (see Figure 13.3). However, the derivative exists at all other points of $f$ i.e., it is 1 on the right side and -1 on the left side. A function can be continuous at a point but not necessarily differentiable there.

# EXERCISE 13.1 

1. Find by definition, the derivatives w.r.t. ' $x$ ' of the following functions defined as:
(i) $2 x^{2}+1$
(ii) $2-\sqrt{x}$
(iii) $\frac{1}{\sqrt{x}}$
(iv) $x(x-3)$
2. Find $\frac{d y}{d x}$ from first principle and find gradient of the curve at the given point:
(i) $\sqrt{x+2}$ at $x=6$
(ii) $\frac{1}{\sqrt{x+a}}$ at $x=a$
3. (i) Find the derivative of $x^{2}$ at $x=8$ from the first principle.
(ii) Find the derivative of $x^{2}+2 x+3$ by definition.
4. Find from first principle, the derivatives of the following expressions w.r.t. their respective independent variables:
(i) $(3 x-2)^{2}$
(ii) $(2 t+3)^{3}$
(iii) $(a w+b)^{7}$
5. Find the gradient and equation of the tangent line to $y=3 x^{2}-4 x+1$ at $x=2$.
6. For the function $f(x)=2 x^{2}+x$, calculate the equation of the tangent line at $x=-1$.
7. Find the coordinates of the point of tangency and the equation of the tangent line for $f(x)=x^{3}-2 x+1$ at $x=1$.
8. Find the gradient of the curve $f(x)=3 x^{2}+2 x$ at $x=1$.
9. Find the gradient and an equation of tangent line to the graph of $f(x)=\sqrt{x}$ at $x=9$
10. The position of a car after $t$ hours is given by: $s(t)=2 t^{2}-3 t^{2}+t$ (in kilometres)
(i) Find the average velocity over the interval $[1,4]$
(ii) Find the instantaneous velocity at $t=2$
11. A stone is thrown upwards and its height after $t$ seconds is given by: $s(t)=-16 t^{2}+32 t+10$ (in feet), Find the instantaneous velocity at $t=1$
12. The outdoor temperature (in ${ }^{\circ} \mathrm{C}$ ) over time is modeled by: $T(t)=-t^{2}+12 t+10$, where $t$ is the time in hours. Find the instantaneous rate of change at $t=2$.

### 13.6 Theorems on Differentiation

We have, so far, proved the following two formulas:

1. $\frac{d}{d x}(c)=0$ that is, the derivative of a constant function is zero.
2. $\frac{d}{d x}\left(x^{n}\right)=n x^{n-1}$, power formula (or rule) when $n$ is any real number.

Now we will prove other important formulas (or rules) which are used to determine derivatives of different functions efficiently. Henceforth, in all subsequent discussion, $f, g, h$ etc, all denote functions differentiable at $x$, unless stated otherwise.
3. Derivative of $y=c f(x)$

Proof: Let $y=c f(x)$, Then
(i) $y+\delta y=c f(x+\delta x)$ and
(ii) $y+\delta y-y=c f(x+\delta x)-c f(x)$
or $\delta y=c[f(x+\delta x)-f(x)]$
(Factoring out $c$ )
(iii) $\frac{\delta y}{\delta x}=c\left[\frac{f(x+\delta x)-f(x)}{\delta x}\right]$

Taking limit when $\delta x \rightarrow 0$
(iv) $\operatorname{Lim}_{\delta x \rightarrow 0} \frac{\delta y}{\delta x}=\operatorname{Lim}_{\delta x \rightarrow 0}\left|c-\frac{f(x+\delta x)-f(x)}{\delta x}\right|=c \operatorname{Lim}_{\delta x \rightarrow 0} \frac{f(x+\delta x)-f(x)}{\delta x}$

A constant factor can be taken out from a limit sign.
Thus, $\frac{d y}{d x}=c f^{\prime}(x)$, that is $[c f(x)]^{\prime}=c f^{\prime}(x)$ or $\frac{d}{d x}[c f(x)]=c \frac{d}{d x}[f(x)]$
Example 6 Calculate $\frac{d}{d x}\left(3 x^{\frac{4}{3}}\right)=3 \frac{d}{d x}\left(x^{\frac{4}{3}}\right)$
(Using Formula 3)
Solution

$$
3 \times \frac{4}{3} x^{\frac{4}{3}-1}=4 x^{\frac{1}{3}}
$$

(Using power rule)
4. Derivative of a sum or a difference of functions

If $f$ and $g$ are differentiable at $x$, then $f+g, f-g$ are also differentiable at $x$ and

$$
[f(x)+g(x)]=f^{\prime}(x)+g^{\prime}(x), \text { that is, } \frac{d}{d x}[f(x)+g(x)]=\frac{d}{d x}[f(x)]+\frac{d}{d x}[g(x)]
$$

Also $[f(x)-g(x)]=f^{\prime}(x)-g^{\prime}(x)$, that is, $\frac{d}{d x}[f(x)-g(x)]=\frac{d}{d x}[f(x)]-\frac{d}{d x}[g(x)]$
Proof: Let $\phi(x)=f(x)+g(x)$. Then
(i) $\phi(x+\delta x)=f(x+\delta x)+g(x+\delta x)$ and
(ii) $\phi(x+\delta x)-\phi(x)=f(x+\delta x)+g(x+\delta x)-[f(x)+g(x)]$

$$
=[f(x+\delta x)-f(x)+[g(x+\delta x)-g(x)] \quad \text { (rearranging the terms) }
$$

(iii) $\frac{\phi(x+\delta x)-\phi(x)}{\delta x}=\frac{f(x+\delta x)-f(x)}{\delta x}+\frac{g(x+\delta x)-g(x)}{\delta x}$

Taking the limit when $\delta x \rightarrow 0$

(iv) $\operatorname{Lim}_{\delta x \rightarrow 0} \frac{\phi(x+\delta x)-\phi(x)}{\delta x}=\operatorname{Lim}_{\delta x \rightarrow 0}\left[\frac{f(x+\delta x)-f(x)}{\delta x}+\frac{g(x+\delta x)-g(x)}{\delta x}\right]$

$$
=\operatorname{Lim}_{\delta x \rightarrow 0} \frac{f(x+\delta x)-f(x)}{\delta x}+\operatorname{Lim}_{\delta x \rightarrow 0} \frac{g(x+\delta x)-g(x)}{\delta x}
$$

(The limit of a sum is the sum of the limits)

$$
\phi^{\prime}(x)=f^{\prime}(x)+g^{\prime}(x), \text { that is }[f(x)+g(x)]^{\prime}=f^{\prime}(x)+g^{\prime}(x)
$$

or $\quad \frac{d}{d x}[f(x)+g(x)]=\frac{d}{d x}[f(x)]+\frac{d}{d x}[g(x)]$
The proof for the second part is similar.
Note Sum or difference formula can be extended to find derivative of more than two functions.
Example 7 Find the derivative of $y=\frac{3}{4} x^{4}+\frac{2}{3} x^{3}+\frac{1}{2} x^{2}+2 x+5$ w.r.t. $x$.
Solution $y=\frac{3}{4} x^{4}+\frac{2}{3} x^{3}+\frac{1}{2} x^{2}+2 x+5$
Differentiating with respect to $x$, we have
$\frac{d y}{d x}=\frac{d}{d x}\left[\frac{3}{4} x^{4}+\frac{2}{3} x^{3}+\frac{1}{2} x^{2}+2 x+5\right]=\frac{d}{d x}\left(\frac{3}{4} x^{4}\right)+\frac{d}{d x}\left(\frac{2}{3} x^{3}\right)+\frac{d}{d x}\left(\frac{1}{2} x^{2}\right)+\frac{d}{d x}(2 x)+\frac{d}{d x}$
(Using formula 4)

$$
\begin{aligned}
& =\frac{3}{4} \frac{d}{d x}\left(x^{4}\right)+\frac{2}{3} \frac{d}{d x}\left(x^{3}\right)+\frac{1}{2} \frac{d}{d x}\left(x^{2}\right)+2 \frac{d}{d x}(x)+0 \quad \text { (Using formula } 3 \text { and } 1) \\
& =\frac{3}{4}\left(4 x^{4-1}\right)+\frac{2}{3}\left(3 x^{3-1}\right)+\frac{1}{2}\left(2 x^{2-1}\right)+2\left(1 . x^{1-1}\right) \quad \text { (By power formula) } \\
& =3 x^{3}+2 x^{2}+x+2
\end{aligned}
$$

Example 8 Find the derivative of $y=\left(x^{2}+5\right)\left(x^{3}+7\right)$ with respect to $x$.
Solution $y=\left(x^{2}+5\right)\left(x^{3}+7\right)=x^{5}+5 x^{3}+7 x^{2}+35$
Differentiating with respect to $x$, we get

$$
\begin{aligned}
\frac{d y}{d x} & =\frac{d}{d x}\left[x^{2}+5 x^{3}+7 x^{2}+35\right] \\
& =\frac{d}{d x}\left(x^{5}\right)+5 \frac{d}{d x}\left(x^{3}\right)+7 \frac{d}{d x}\left(x^{2}\right)+\frac{d}{d x}(35) \quad \text { (Using formulas } 3 \text { and } 4) \\
& =5 x^{5-1}+5 \times 3 x^{3-1}+7 \times 2 x^{2-1}+0 \\
& =5 x^{4}+15 x^{2}+14 x
\end{aligned}
$$

Example 5 Find the derivative of $y=(2 \sqrt{x}+2)(x-\sqrt{x})$

Solution $y=(2 \sqrt{x}+2)(x-\sqrt{x})$

$$
\begin{aligned}
& =2(\sqrt{x}+1) \cdot \sqrt{x}(\sqrt{x}-1)=2 \sqrt{x}(\sqrt{x}+1)(\sqrt{x}-1) \\
& =2 \sqrt{x}(x-1)=2\left(x^{\frac{3}{2}}-x^{\frac{1}{2}}\right)
\end{aligned}
$$

Differentiating with respect to $x$ we have

$$
\begin{aligned}
\frac{d y}{d x} & =\frac{d}{d x}\left[2\left(x^{\frac{3}{2}}-x^{\frac{1}{2}}\right)\right] \\
& =2\left[\frac{d}{d x} x^{\frac{3}{2}}-\frac{d}{d x} x^{\frac{1}{2}}\right]=2\left[\frac{3}{2} x^{\frac{3}{2}-1}-\frac{1}{2} x^{\frac{1}{2}-1}\right] \\
& =3 x^{\frac{1}{2}}-x^{-\frac{1}{2}}=3 \sqrt{x}-\frac{1}{\sqrt{x}}=\frac{3 x-1}{\sqrt{x}}
\end{aligned}
$$

# 5. Derivative of a Product (The Product Rule) 

If $f$ and $g$ are differentiable at $x$, then $f g$ is also differentiable at $x$ and

$$
\begin{gathered}
{[f(x) g(x)]^{\prime}=f^{\prime}(x) g(x)+f(x) g^{\prime}(x) \text {, that is }} \\
\frac{d}{d x}[f(x) g(x)]=\left[\frac{d}{d x}[f(x)]\right] g(x)+f(x)\left[\frac{d}{d x}[g(x)]\right]
\end{gathered}
$$

Proof: Let $\phi(x)=f(x) g(x)$. Then
(i) $\phi(x+\delta x)=f(x+\delta x) g(x+\delta x)$ and
(ii) $\phi(x+\delta x)-\phi(x)=f(x+\delta x) g(x+\delta x)-f(x) g(x)$

Subtracting and adding $f(x) g(x+\delta x)$ in step (ii), gives

$$
\begin{gathered}
\phi(x+\delta x)-\phi(x)=f(x+\delta x) g(x+\delta x)-f(x) g(x+\delta x)+f(x) g(x+\delta x)-f(x) g(x) \\
=[f(x+\delta x)-f(x)] g(x+\delta x)+f(x)[g(x+\delta x)-g(x)]
\end{gathered}
$$

(iii) $\frac{\phi(x+\delta x)-\phi(x)}{\delta x}=\left[\frac{f(x+\delta x)-f(x)}{\delta x}\right] g(x+\delta x)+f(x)\left[\frac{g(x+\delta x)-g(x)}{\delta x}\right]$

Taking limit when $\delta x \rightarrow 0$

(iv) $\lim _{\delta x \rightarrow 0} \frac{\phi(x+\delta x)-\phi(x)}{\delta x}$

$$
\begin{aligned}
& =\lim _{\delta x \rightarrow 0}\left[\frac{f(x+\delta x)-f(x)}{\delta x} \cdot g(x+\delta x)+f(x) \cdot \frac{g(x+\delta x)-g(x)}{\delta x}\right] \\
& =\lim _{\delta x \rightarrow 0} \frac{f(x+\delta x)-f(x)}{\delta x} \cdot \lim _{\delta x \rightarrow 0} g(x+\delta x)+\lim _{\delta x \rightarrow 0} f(x) \cdot \lim _{\delta x \rightarrow 0} \frac{g(x+\delta x)-g(x)}{\delta x}
\end{aligned}
$$

(Using limit theorem)
Thus $\phi^{\prime}(x)=f^{\prime}(x) g(x)+f(x) g^{\prime}(x) \quad\left[\operatorname{Lim}_{\delta x \rightarrow 0} g(x+\delta x)=g(x)\right]$
or $\quad \frac{d}{d x}[f(x) \cdot g(x)]=\frac{d}{d x}[f(x)] \cdot g(x)+f(x)\left[\frac{d}{d x} g(x)\right]$
Example 10 Find derivative of $y=(2 \sqrt{x}+2)(x-\sqrt{x})$ with respect to $x$.
Solution $y=(2 \sqrt{x}+2)(x-\sqrt{x})$

$$
=2(\sqrt{x}+1)(x-\sqrt{x})
$$

Differentiating with respect to $x$, we get

$$
\begin{aligned}
\frac{d y}{d x} & =2 \frac{d}{d x}[(\sqrt{x}+1)(x-\sqrt{x})] \\
& =2\left[\left(\frac{d}{d x}(\sqrt{x}+1)\right)(x-\sqrt{x})+(\sqrt{x}+1) \frac{d}{d x}(x-\sqrt{x})\right] \\
& =2\left[\left(\frac{1}{2} x^{\frac{1}{2}-1}+0\right)(x-\sqrt{x})+(\sqrt{x}+1) \times\left(1-\frac{1}{2} x^{\frac{1}{2}-1}\right)\right] \\
& =2\left[\frac{1}{2 \sqrt{x}}(x-\sqrt{x})+(\sqrt{x}+1) \times\left(1-\frac{1}{2 \sqrt{x}}\right)\right] \\
& =2\left[\frac{x-\sqrt{x}}{2 \sqrt{x}}+(\sqrt{x}+1)\left(\frac{2 \sqrt{x}-1}{2 \sqrt{x}}\right)\right] \\
& =\frac{1}{\sqrt{x}}[x-\sqrt{x}+2 x-\sqrt{x}+2 \sqrt{x}-1] \\
& =\frac{3 x-1}{\sqrt{x}}
\end{aligned}
$$

# 6. Derivative of a Quotient (The Quotient Rule) 

If $f$ and $g$ are differentiable at $x$ and $g(x) \neq 0$, for any $x \in D(g)$ then $\frac{f}{g}$ is differentiable at $x$ and $\left(\frac{f(x)}{g(x)}\right)^{\prime}=\frac{f^{\prime}(x) g(x)-f(x) g^{\prime}(x)}{[g(x)]^{2}}$
that is $\frac{d}{d x}\left[\frac{f(x)}{g(x)}\right]=\frac{\left[\frac{d}{d x}[f(x)] g(x)-f(x)\left[\frac{d}{d x}[g(x)]\right.\right.}{[g(x)]^{2}}$
Proof: Let $\phi(x)=\frac{f(x)}{g(x)}$. Then
(i) $\phi(x+\delta x)=\frac{f(x+\delta x)}{g(x+\delta x)}$ and
(ii) $\phi(x+\delta x)-\phi(x)=\frac{f(x+\delta x)}{g(x+\delta x)}-\frac{f(x)}{g(x)}=\frac{f(x+\delta x) g(x)-f(x) g(x+\delta x)}{g(x) g(x+\delta x)}$

Subtracting and adding $f(x) g(x)$ in the numerator of step (ii), gives

$$
\begin{aligned}
\phi(x+\delta x)-\phi(x) & =\frac{f(x+\delta x) g(x)-f(x) g(x)-f(x) g(x+\delta x)+f(x) g(x)}{g(x) g(x+\delta x)} \\
& =\frac{1}{g(x) g(x+\delta x)}[(f(x+\delta x)-f(x)) g(x)-f(x)(g(x+\delta x)-g(x))]
\end{aligned}
$$

(iii) $\frac{\phi(x+\delta x)-\phi(x)}{\delta x}=\frac{1}{g(x) g(x+\delta x)}\left[\frac{f(x+\delta x)-f(x)}{\delta x} \cdot g(x)-f(x) \cdot \frac{g(x+\delta x)-g(x)}{\delta x}\right]$

Taking limit when $\delta x \rightarrow 0$
(iv) $\lim _{\delta x \rightarrow 0} \frac{\phi(x+\delta x)-\phi(x)}{\delta x}$

$$
=\lim _{d x \rightarrow 0}\left[\frac{1}{g(x) g(x+\delta x)}\left(\frac{f(x+\delta x)-f(x)}{\delta x} \cdot g(x)-f(x) \cdot \frac{g(x+\delta x)-g(x)}{\delta x}\right)\right]
$$

Using limit theorems, we have

$$
\phi^{\prime}(x)=\frac{1}{g(x) \cdot g(x)}\left[f^{\prime}(x) g(x)-f(x) g^{\prime}(x)\right] \quad\left(\because \underset{\text { iix } \rightarrow 0}{ } g(x+\delta x)=g(x)\right)
$$

Thus $\quad\left(\frac{f(x)}{g(x)}\right)=\frac{f^{\prime}(x) g(x)-f(x) g^{\prime}(x)}{[g(x)]^{2}}$
or $\quad \frac{d}{d x}\left(\frac{f(x)}{g(x)}\right)=\frac{\left[\frac{d}{d x}(f(x))\right] g(x)-f(x)\left[\frac{d}{d x}(g(x))\right]}{[g(x)]^{2}}$
Example11 Differentiate $\frac{2 x^{2}-3 x^{2}+5}{x^{2}+1}$ with respect to $x$.
Solution Let $\phi(x)=\frac{2 x^{2}-3 x^{2}+5}{x^{2}+1}$. Then

$$
f(x)=2 x^{3}-3 x^{2}+5 \quad \text { and } \quad g(x)=x^{2}+1
$$

Now

$$
f^{\prime}(x)=\frac{d}{d x}\left[2 x^{3}-3 x^{2}+5\right]=2\left(3 x^{2}\right)-3(2 x)+0=6 x^{2}-6 x
$$

and

$$
g^{\prime}(x)=\frac{d}{d x}\left[x^{2}+1\right]=2 x+0=2 x
$$

Using the quotient formula $\phi^{\prime}(x)=\frac{f^{\prime}(x) g(x)-f(x) g^{\prime}(x)}{[g(x)]^{2}}$, We obtain

$$
\begin{aligned}
\frac{d}{d x}\left[\frac{2 x^{3}-3 x^{2}+5}{x^{2}+1}\right] & =\frac{\left(6 x^{2}-6 x\right)\left(x^{2}+1\right)-\left(2 x^{2}-3 x^{2}+5\right)(2 x)}{\left(x^{2}+1\right)^{2}} \\
& =\frac{6 x^{4}-6 x^{3}+6 x^{2}-6 x-\left(4 x^{4}-6 x^{3}+10 x\right)}{\left(x^{2}+1\right)^{2}} \\
& =\frac{6 x^{4}-6 x^{3}+6 x^{2}-6 x-4 x^{4}+6 x^{3}-10 x)}{\left(x^{2}+1\right)^{2}} \\
& =\frac{2 x^{4}+6 x^{3}-16 x}{\left(x^{2}+1\right)^{2}}
\end{aligned}
$$

# EXERCISE 13.2 

1. Differentiate w.r.t ' $x$ '.
(i) $x^{4}+2 x^{3}+x^{2}$
(ii) $x^{-3}+2 \overline{x^{2}}+3$
(iii) $\frac{2 x-3}{2 x+1}$
(iv) $\frac{(1+\sqrt{x})(x-x)}{\sqrt{x}}$
(v) $\left(\sqrt{x} \frac{1}{\sqrt{x}}\right)^{2}$
(vi) $(x-5)(3-x)$

(vii) $\frac{\left(x^{2}+1\right)^{2}}{x^{2}-1}$
(viii) $\frac{x^{2}+1}{x^{2}-3}$
(ix) $\frac{2 x-1}{\sqrt{x^{2}+1}}$
(x) $\sqrt{\frac{a-x}{a+x}}$
(xi) $\frac{\sqrt{x^{2}+1}}{\sqrt{x^{2}-1}}$
2. Find $\frac{d y}{d x}$ if $y=\frac{(\sqrt{x}+1)\left(x^{\frac{3}{2}}-1\right)}{x^{\frac{1}{2}}-1},(x \neq 1)$
3. Differentiate $\frac{(\sqrt{x}+1)\left(x^{\frac{3}{2}}-1\right)}{x^{\frac{1}{2}}-x^{\frac{1}{2}}}$ with respect to $x$.
4. If $y=\sqrt{x}-\frac{1}{\sqrt{x}}$, show that $2 x \frac{d y}{d x}+y=2 \sqrt{x}$
5. If $y=x^{4}+2 x^{2}+2$, prove that $\frac{d y}{d x}=4 x \sqrt{y-1}$.

# 13.7 Application of Differentiation 

We will apply concept of differentiatioñ to real-world problems such as (profits on diminishing returns, environmental factors, financial investments, population growth, spread of diseases, movement of particles, time-speed in transportation, structural stress, material required that is changes in construction).
Profits on Diminishing Returns
Example 12 A company's profit function is given by $P(x)=100 x-5 x^{2}$, where $x$ is the number of units produced. Determine the marginal profit when $x=8$ units.
Solution The marginal profit is the derivative of the profit function with respect to $x$.
$P^{\prime}(x)=\frac{d}{d x}\left(100 x-5 x^{2}\right)=100-10 x$
Now, substitute $x=8: P^{\prime}(8)=100-10(8)=20$
So, the marginal profit is 20 when 8 units are produced (in the given currency).
Movement of Particles
Example 13 A particle moves along a line according to the position function $s(t)=4 t^{3}-3 t^{2}+2 t$, where $s(t)$ is the position in metres and $t$ is the time in seconds. Find the velocity and acceleration at $t=2$ seconds.
Solution Velocity is the derivative of the position function:

$$
v(t)=\frac{d}{d t}\left(4 t^{3}-3 t^{2}+2 t\right)=12 t^{2}-6 t+2
$$

Substitute $t=2$ :

$$
v(2)=12(2)^{2}-6(2)+2=48-12+2=38
$$

So, the velocity at $t=2$ is $38 \mathrm{~m} / \mathrm{s}$.
Acceleration is the derivative of the velocity function:

$$
a(t)=\frac{d}{d t}\left(12 t^{2}-6 t+2\right)=24 t-6
$$

Substitute $t=2$

$$
a(2)=24(2)-6=48-6=42
$$

So, the acceleration at $t=2$ is $42 \mathrm{~m} / \mathrm{s}^{2}$.

# Financial Investments 

Example 14 A bank offers a compound interest rate on an investment, and the value of the investment after $t$ years is given by $V(t)=5000(1+0.04 t)^{2}$. Find the rate of change of the investment value after 10 years.
Solution The rate of change of the investment is the derivative of $V(t)$ with respect to $t$.

$$
\begin{aligned}
& V^{\prime}(t)=\frac{d}{d t}\left(5000(1+0.04 t)^{2}\right)=5000(2)(1+0.04 t)(0.04) \\
& V^{\prime}(t)=400(1+0.04 t)
\end{aligned}
$$

Substitute $t=10$ :

$$
V^{\prime}(10)=400(1+0.04 \times 10)=400(1+0.40)=400 \times 1.4=560
$$

So, the investment is growing at a rate of Rs. 560 per year after 10 years.

## Structural Stress

Example 15 The stress on a beam under a varying load is modeled by $S(x)=500 x-2 x^{2}$, where $S(x)$ is the stress in pascals ( Pa ) and $x$ is the distance (in metres) from the beam's fixed end. Find the rate of change of stress at $x=5$ metres.
Solution The rate of change of stress is the derivative of $S(x)$ with respect to $x$.

$$
S^{\prime}(x)=\frac{d}{d x}\left(500 x-2 x^{2}\right)=500-6 x^{2}
$$

Substitute $x=5$ :

$$
S^{\prime}(5)=500-6(5)^{2}=500-6 \times 25=500-150=350
$$

So, the stress is increasing at a rate of 350 Pa per metre at $x=5$ metres.

## EXERCISE 13.3

1. A car's position at time $t$ is given by $s(t)=5 t^{2}-3 t^{2}+t$. Find the velocity by differentiating the position function with respect to time.
2. Structural stress on a bridge is modeled by the function $S(x)=100-5 x^{2}$, where $x$ is the distance from the center of the bridge. Calculate the rate of change of stress at that point.

3. A company's revenue function is given by $R(x)=1000 x-10 x^{2}$, where is the number of units produced. The cost function is $C(x)=300 x+2000$.
(i) Find the profit function $P(x)$
(ii) Determine the marginal profit when $x=15$
4. An investment grows according to the function $A(t)=10000(1+0.05 t)^{3}$, where $A(t)$ is the value of the investment and $t$ is the time in years.
(i) Find the rate of change of the investment after 8 years.
(ii) What is the investment value after 8 years?
5. The position of a particle moving along a line is given by $s(t)=5 t^{1}-12 t^{2}+8 t$, where $s(t)$ is the position in meters and $t$ is the time in seconds.
(i) Determine the velocity of the particle at $t=4$ seconds
(ii) Find the acceleration at $t=4$ seconds
(iii) When is the particle at rest?
6. The position of a car traveling along a straight highway is given by $x(t)=30 t^{2}-4 t^{3}$, where $x(t)$ is the distance traveled in kilometres and $t$ is the time in hours.
(i) Find the car's velocity at $t=3$ hours.
(ii) Determine the car's acceleration at $t=3$ hours
7. The stress on a beam under a varying load is given by $S(x)=400 x-x^{3}$, where $S(x)$ is the stress in pascals ( Pa ) and $x$ is the distance from the fixed end in metres. Calculate the rate of change of stress at 6 meters.
8. The cost $C(r)$ to construel a cylindrical tank depends on the radius of the base, and is given by $C(r) \leq 8000 \mathrm{~m}^{2}+\frac{150000}{r}$, where the first term represents the cost of the base and the second term represents the cost of the walls. Determine the rate of change of the cost at $r=4$ metres.

# Vectors in Space 

## INTRODUCTION

In this unit, we will look into the rectangular coordinate system in three-dimensional space and explore the fundamental mathematical operations involving vectors in space. We will begin by understanding the dot product (or scalar product) and the cross product (or vector product) of two vectors and learn about their geometric interpretation. Further, we emphasize their practical applications. For example, we will see how these concepts can be used to calculate the area of a triangle and the area of a parallelogram. Finally, we will explore the extensive use of vectors in three-dimensional space, particularly in physics, where they play an important role in determining forces, velocities, and other essential physical quantities. For example, determining the work done by a constant force when moving an object along a specified vector.

### 14.1 Vectors (Recall)

In previous classes, we learned about two fundamental quantities: scalars and vectors. A scalar is a quantity that has only magnitude or size, such as mass, time, density, temperature, length, volume, speed, work etc. On the other hand, a vector is a quantity that has both magnitude and direction, for example displacement, velocity, acceleration, weight, force, momentum, electric and magnetic fields, etc.
Geometrically, a vector is represented as a directed line segment $\overrightarrow{A B}$ with $A$ as its initial point and $B$ as the terminal point.
In two-dimension $\left(R^{2}\right)$ a vector has components that can be represented by an ordered pair $[x, y]$ of real numbers. For the vector $\underline{u}=[x, y], x$ and $y$ represent the components of $\underline{u}$.
Addition of Vectors: For any two vectors $\underline{u}=\left[x_{1}, y_{1}\right]$ and $\underline{y}=\left[x_{2}, y_{2}\right]$, we have

$$
\underline{u}+\underline{y}=\left[x_{1}, y_{1}\right]+\left[x_{2}, y_{2}\right]=\left[x_{1}+x_{2}, y_{1}+y_{2}\right]
$$

Scalar Multiplication of a Vector: For $\underline{u}=[x, y]$ and $a \in R$, we have

$$
a \underline{u}=a[x, y]=[a x, a y]
$$

Equal Vectors: Two vectors $\underline{u}=\left[x_{1}, y_{1}\right]$ and $\underline{y}=\left[x_{2}, y_{2}\right]$ of $R^{2}$ are said to be equal

if and only if they have the same components. That is, $\left[x_{1}, y_{1}\right]=\left[x_{2}, y_{2}\right]$ if and only if $x_{1}=x_{2}$ and $y_{1}=y_{2}$ and we write $\underline{u}=\underline{v}$
In other words, two vectors $\underline{u}$ and $\underline{v}$ are said to be equal, if they have same magnitude and same direction.
[Image removed]

Parallel Vectors: Two vectors are parallel if and only if they are non-zero scalar multiple of each other.
For example, vectors $\overrightarrow{A B},-\overrightarrow{A B}$ and $\frac{3}{2} \overrightarrow{A B}$ are parallel.

# Magnitude of a Vector 

The magnitude (or norm or length) of a vector in 2D represents the length of the vector from the origin to the point represented by the vector. For any vector $\underline{u}=[x, y]$ in $R^{2}$, we define the magnitude, as the distance of the point $P(x, y)$ from the origin $O$.

Magnitude of $\overrightarrow{O P}=|\overrightarrow{O P}|=|\underline{u}|=\sqrt{x^{2}+y^{2}}$
Now, we will learn some mathematical operations involving vectors in three-dimensional space.

### 14.1.1 Rectangular Coordinate System in Space

In space a rectangular coordinate system is constructed using three mutually orthogonal (perpendicular) axes, which have origin as their common point of intersection. When sketching figures, we follow the convention that the positive $x$-axis points towards the reader, the positive $y$-axis to the right and the positive $z$-axis points upwards.
[Image removed]

These axes are also labeled in accordance with the righthand rule. The fingers of the right hand, pointing in the direction of the positive $x$-axis, curled images toward the positive $y$-axis, and the thumb will point in the direction of the positive $z$-axis. A point $P$ in space has three coordinates, one along $x$-axis, the second along $y$-axis and the third along $z$-axis. If the
[Image removed]

Right hand rule

# Unit 44 Vectors in Space 

directed distances along $x$-axis, $y$-axis and $z$-axis respectively are $a, b$ and $c$, then the point $P$ is written with a unique triple of real numbers as $P(a, b, c)$ (see figure).

### 14.1.2 Concept of a Vector in Space

The set $R^{3}=\{(x, y, z): x, y, z \in R\}$ is called 3-dimensional space. An element $(x, y, z)$ of $R^{3}$ represents a point $P(x, y, z)$, which is uniquely determined by its coordinates $x, y$ and $z$. Given a vector $\underline{u}$ in space, there exists a unique point $P(x, y, z)$ in space such that the vector $\overrightarrow{O P}$ is equal to $\underline{u}$ (see figure). Now each element $(x, y, z) \in R^{3}$ is associated with a unique ordered triple $(x, y, z)$, which represents the vector $\underline{u}=\overrightarrow{O P}=[x, y, z]$.

### 14.1.3 Fundamental Mathematical Operations for Vectors in Space

We define addition and scalar multiplication in $R^{3}$ by:
(i) Addition of Vectors: For any two vectors $\underline{u}=[x, y, z]$ and $\underline{y}=\left[x^{\prime}, y^{\prime}, z^{\prime}\right]$ we have $\underline{u}+\underline{v}=[x, y, z]+\left[x^{\prime}, y^{\prime}, z^{\prime}\right]=\left[x+x^{\prime}, y+y^{\prime}, z+z^{\prime}\right]$
(ii) Scalar Multiplication of a Vector: For $\underline{u}=[x, y, z]$ and $a \in R$, we have $a \underline{u}=a[x, y, z]=[a x, a y, a z]$
The set of all ordered triples $[x, y, z]$ of real numbers, together with the rules of addition and scalar multiplication is called the set of vectors in $R^{3}$. For the vector $\underline{u}=[x, y, z], x, y$ and $z$ are called the components of $\underline{u}$. The definition of vectors in $R^{3}$ states that vector addition and scalar multiplication are to be carried out also for vectors in space just as for vectors in the plane. Similarly, we define in $R^{3}$ :
(a) The negative of the vector $\underline{u}=[x, y, z]$ as $-\underline{u}=(-1) \underline{u}=[-x,-y,-z]$
(b) The difference of two vectors $\underline{y}=\left[x^{\prime}, y^{\prime}, z^{\prime}\right]$ and $\underline{w}=\left[x^{\prime \prime}, y^{\prime \prime}, z^{\prime \prime}\right]$ as

$$
\underline{v}-\underline{w}=\underline{v}+(-\underline{w})=\left[x^{\prime}-x^{\prime \prime}, y^{\prime}-y^{\prime \prime}, z^{\prime}-z^{\prime \prime}\right]
$$

(c) The zero vector as $O=[0,0,0]$
(d) Equality of two vectors: Two vectors $\underline{y}=\left[x^{\prime}, y^{\prime}, z^{\prime}\right]$ and $\underline{w}=\left[x^{\prime \prime}, y^{\prime \prime}, z^{\prime \prime}\right]$ are equal that is $\underline{v}=\underline{w}$ if and only if $x^{\prime}=x^{\prime \prime}, y^{\prime}=y^{\prime \prime}$ and $z^{\prime}=z^{\prime \prime}$.
(e) Position Vector

For any point $P(x, y, z)$ in $R^{3}$, a vector $\underline{u}=[x, y, z]$ is represented by a directed line segment $\overrightarrow{O P}$, whose initial point is at origin. Such vectors are called position vectors in $R^{3}$.

# 14.1.4 Magnitude of a Vector in Space 

We define the magnitude, norm, or length of a vector $\underline{u}=[x, y, z]$ in space by the distance of the point $P(x, y, z)$ from the origin $O$.

$$
\therefore \quad \overrightarrow{O P}=|u|=\sqrt{x^{2}+y^{2}+z^{2}}
$$

Example 1 For the vectors, $\underline{u}=[1,-2,3], \underline{y}=[2,1,3]$ and $\underline{w}=[-1,4,0]$, find the following:
(i) $\underline{y}+\underline{w}$
(ii) $2 \underline{w}$
(iii) $|u|$
(iv) $|\underline{v}-2 \underline{w}|$
(v) $|2 \underline{u}-\underline{y}+3 \underline{w}|$

Solution (i) $\quad \underline{y}+\underline{w}=[2-1,1+4,3+0]=[1,5,3]$
(ii) $2 \underline{w}=2[-1,4,0]=[-2,8,0]$
(iii) $|u|=[1,-2,3]=\sqrt{(1)^{2}+(-2)^{2}+(3)^{2}}=\sqrt{1+4+9}=\sqrt{14}$
(iv) $|\underline{v}-2 \underline{w}|=|[2+2,1-8,3-0]|=|[4,-7,3]|$

$$
=\sqrt{(4)^{2}+(-7)^{2}+(3)^{2}}=\sqrt{16+49+9}=\sqrt{74}
$$

(v) $|2 \underline{u}-\underline{y}+3 \underline{w}|=|2[1,-2,3]-[2,1,3]+3[-1,4,0]|=|[2,-4,6]-[2,1,3]+[-3,12,0]|$

$$
=[-3,7,3]=\sqrt{(-3)^{2}+(7)^{2}+(3)^{2}}=\sqrt{9+49+9}=\sqrt{67}
$$

### 14.1.5 Components of a Vector

As in plane, we introduce three special vectors $i=[1,0,0]$, $j=[0,1,0]$ and $k=[0,0,1]$ in $R^{3}$

As magnitude of $i=\sqrt{1^{2}+0^{2}+0^{2}}=1$
magnitude of $j=\sqrt{0^{2}+1^{2}+0^{2}}=1$ and
magnitude of $k=\sqrt{0^{2}+0^{2}+1^{2}}=1$. So, $i, j$
[Image removed]
and $k$ are called unit vectors along $x$-axis, $y$-axis and $z$-axis respectively. Using the definition of addition and scalar multiplication, the vector $[x, y, z]$ can be written as:

$$
\begin{aligned}
\underline{u}=[x, y, z] & =[x, 0,0]+[0, y, 0]+[0,0, z] \\
& =x[1,0,0]+y[0,1,0]+z[0,0,1]=x i+y j+z k
\end{aligned}
$$

Thus, each vector $[x, y, z]$ in $R^{3}$ can be uniquely represented by $x i+y i+z k$.

## Unit Vector

A unit vector is defined as a vector whose magnitude is unity. In three-dimensional space the unit vector of the vector $\underline{u}=x i+y j+z k$ is written as $\hat{u}$ (read as $u$ hat) and

is defined by

$$
\hat{u}=\frac{u}{|u|}=\frac{x}{\sqrt{x^{2}+y^{2}+z^{2}}} i+\frac{y}{\sqrt{x^{2}+y^{2}+z^{2}}} j+\frac{z}{\sqrt{x^{2}+y^{2}+z^{2}}} k
$$

In terms of unit vector $i, j$, and $k$, the sum $u+y$ of two vectors.
$\underline{u}=\left[x_{1}, y_{1}, z_{1}\right]$ and $y=\left[x_{2}, y_{2}, z_{2}\right]$ is written as:

$$
\begin{aligned}
\underline{u}+\underline{v} & =\left[x_{1}+x_{2}, y_{1}+y_{2}, z_{1}+z_{2}\right] \\
& =\left(x_{1}+x_{2}\right) i+\left(y_{1}+y_{2}\right) j+\left(z_{1}+z_{2}\right) k
\end{aligned}
$$

Example 2 Find the unit vector of $\underline{u}=2 i+5 j-k$.
Solution Given vector $\underline{u}=2 i+5 \underline{j}-k$, to find the unit vector

$$
\begin{aligned}
& \Rightarrow \quad|u|=\sqrt{(2)^{2}+(5)^{2}+(-1)^{2}}=\sqrt{30} \\
& \quad \text { The unit vector is: } \\
& \Rightarrow \quad \hat{u}=\frac{u}{|u|}=\frac{2 i+5 j-k}{\sqrt{30}}=\frac{1}{\sqrt{30}}(2 i+5 j-k)
\end{aligned}
$$

Thus, $\hat{u}=\frac{1}{\sqrt{30}}(2 i+5 j-k)$ is the required unit vector.
Example 3 If $\underline{u}=2 i+3 j+k, \underline{v}=4 i+6 j+2 k$ and $\underline{w}=-6 i-9 j-3 k$, then show that $\underline{u}, \underline{v}$ and $\underline{w}$ are parallel to each other.
Solution $\quad \underline{v}=4 i+6 j+2 k=2(2 i+3 j+k)$

$$
\therefore \quad \underline{v}=2 \underline{u}
$$

$\Rightarrow \underline{u}$ and $\underline{v}$ are parallel vectors.

$$
\begin{aligned}
& \underline{w}=-6 i-9 j-3 k \\
& =-3(2 i+3 j+k) \quad \therefore \quad \underline{w}=-3 \underline{u}
\end{aligned}
$$

$\Rightarrow \underline{u}$ and $\underline{w}$ are parallel vectors.
Hence $\underline{u}, \underline{v}$ and $\underline{w}$ are parallel to each other.

# 14.1.6 Properties of Vectors 

Let $\underline{u}, \underline{v}$ and $\underline{w}$ be vectors in the plane or in space and let $a, b \in R$, then they have the following properties:
(i) $\underline{u}+\underline{v}=\underline{v}+\underline{u}$
(Commutative property)
(ii) $(\underline{u}+\underline{v})+\underline{w}=\underline{u}+(\underline{v}+\underline{w})$
(Associative property)
(iii) $\underline{u}+\underline{o}=\underline{u}$
(Additive Identity)
(iv) $\underline{u}+(-1) \underline{u}=\underline{u}-\underline{u}=\underline{o}$
(Inverse for vector addition)
(v) $a(\underline{v}+\underline{w})=a \underline{v}+\alpha \underline{w}$
(Distributive property)
(vi) $a(b \underline{u})=(a b) \underline{u}$
(Scalar multiplication)

Proof: (i) Since for any two real numbers $a, b \in R, a+b=b+a$, it follows that for any two vectors $\underline{u}=[x, y, z]$ and $\underline{y}=\left[x^{\prime}, y^{\prime}, z^{\prime}\right]$ in $R^{3}$, where components of $\underline{u}$ and $\underline{y}$ belong to $R$.
We have

$$
\begin{aligned}
\underline{u}+\underline{y} & =[x, y, z]+\left[x^{\prime}, y^{\prime}, z^{\prime}\right] \\
& =\left[x+x^{\prime}, y+y^{\prime}, z+z^{\prime}\right] \\
& =\left[x^{\prime}+x, y^{\prime}+y, z^{\prime}+z\right] \quad \because \quad a+b=b+a \\
& =\left[x^{\prime}, y^{\prime}, z^{\prime}\right]+[x, y, z] \\
& =\underline{y}+\underline{u}
\end{aligned}
$$

So, addition of vectors in $R^{3}$ is commutative.
(ii) Since for any three real numbers $a, b, c \in R,(a+b)+c=a+(b+c)$, it follows that for any three vectors, $\underline{u}=[x, y, z], \underline{y}=\left[x^{\prime}, y^{\prime}, z^{\prime}\right]$ and $\underline{w}=\left[x^{\prime \prime}, y^{\prime \prime}, z^{\prime \prime}\right]$ in $R^{3}$. Where components of $\underline{u}, \underline{y}$ and $\underline{w}$ belong to $R$.
We have

$$
\begin{aligned}
(\underline{u}+\underline{y})+\underline{w} & =\left[x+x^{\prime}, y+y^{\prime}, z+z^{\prime}\right]+\left[x^{\prime \prime}, y^{\prime \prime}, z^{\prime \prime}\right] \\
& =\left[\left(x+x^{\prime}\right)+x^{\prime \prime},\left(y+y^{\prime}\right)+y^{\prime \prime},\left(z+z^{\prime}\right)+z^{\prime \prime}\right] \\
& =\left[x+\left(x^{\prime}+x^{\prime \prime}\right), y+\left(y^{\prime}+y^{\prime \prime}\right), z+\left(z^{\prime}+z^{\prime \prime}\right)\right] \\
& \because \quad(a+b)+c=a+(b+c) \\
& =[x, y, z]+\left[x^{\prime}+x^{\prime \prime}, y^{\prime}+y^{\prime \prime}, z^{\prime}+z^{\prime \prime}\right] \\
& =\underline{u}+(\underline{y}+\underline{w})
\end{aligned}
$$

So, addition of vectors in $R^{3}$ is associative.
(iii) Since for any real number $a$ and 0

$$
a+0=a, \text { it follows that }
$$

for any vectors, $\underline{u}=[x, y, z]$, and $\underline{o}=[0,0,0]$, where $\underline{o}$ is the zero vector in $R^{3}$.
We have

$$
\begin{aligned}
\underline{u}+\underline{o} & =[x, y, z]+[0,0,0] \\
& =[x+0, y+0, z+0] \\
& =[x, y, z]=\underline{u} \\
\underline{u}+\underline{o} & =\underline{u}
\end{aligned}
$$

Thus, $\underline{o}$ is the additive identity in $\mathrm{R}^{3}$
(iv) Since for any real number $a$, there exist $-a$ such that

$$
a+(-a)=a-a=0 \quad, \quad \text { it follows that }
$$

for any vector, $\underline{u}=[x, y, z]$, there exists $-\underline{u}=[-x,-y,-z]$ in $R^{3}$
Such that

$$
\begin{aligned}
\underline{u}+(-\underline{u}) & =[x, y, z]+[-\infty x,-y,-z]=[x+(-x), y+(-y), z+(-z)] \\
& =[x-x, y-y, z-z] \\
& =[0,0,0]=\underline{o}, \text { where } \underline{o} \text { is the additive identity } \\
\underline{u}+(-\underline{u}) & =\underline{o}
\end{aligned}
$$

Thus $-\underline{u}$ is the additive inverse of $\underline{u}$ in $\mathrm{R}^{3}$
The proofs of the other parts are left as an exercise for the students.

# 14.1.7 Distance Between Two Points in Space 

If $\overrightarrow{O P_{1}}$ and $\overrightarrow{O P_{2}}$ are the position vectors of the points $P_{1}\left(x_{1}, y_{1}, z_{1}\right)$ and $P_{2}\left(x_{2}, y_{2}, z_{2}\right)$
The vector $\overrightarrow{P_{1} P_{2}}$ is given by

$$
\overrightarrow{P_{1} P_{2}}=\overrightarrow{O P_{2}}-\overrightarrow{O P_{1}}=\left[x_{2}-x_{1}, y_{2}-y_{1}, z_{2}-z_{1}\right]
$$

Distance between $P_{1}$ and $P_{2}=\left|\overrightarrow{P_{1} P_{2}}\right|$

$$
=\sqrt{\left(x_{2}-x_{1}\right)^{2}+\left(y_{2}-y_{1}\right)^{2}+\left(z_{2}-z_{1}\right)^{2}}
$$

[Image removed]

This is called distance formula between two points $P_{1}$ and $P_{2}$ in $R^{3}$.
Example 4 Suppose a butterfly's flight path passed through points $(2,4,7)$ and $(6,1,3)$, where each unit represents a metre. What is the magnitude of the displacement the butterfly experienced in traveling between these two points?
Solution Distance between two points in three-dimensional space is given by the formula

$$
d=\sqrt{\left(x_{2}-x_{1}\right)^{2}+\left(y_{2}-y_{1}\right)^{2}+\left(z_{2}-z_{1}\right)^{2}}
$$

Substitute the coordinates of the given points into the formula:

$$
\begin{aligned}
& d=\sqrt{(6-2)^{2}+(1-4)^{2}+(3-7)^{2}} \\
& d=\sqrt{16+9+16}=\sqrt{41}=6.40
\end{aligned}
$$

The magnitude of the displacement the butterfly experienced in traveling between these two points is approximately 6.40 metres.

### 14.1.8 Direction Angles and Direction Cosines of a Vector

Let $r=\overrightarrow{O P}=x i+y j+z k$ be a non-zero vector, let $\alpha, \beta$ and $\gamma$ denote the angles formed between $r$ and the unit coordinate vectors $i, j$ and $k$ respectively,
where $0 \leq \alpha \leq \pi, 0 \leq \beta \leq \pi$ and $0 \leq \gamma \leq \pi$
(i) The angles $\alpha, \beta$ and $\gamma$ are called the direction angles of the vector $r$.
[Image removed]
(ii) The numbers $\cos \alpha, \cos \beta$ and $\cos \gamma$ are called direction cosines of the vector $r$.

# Important Result: 

Prove that $\cos ^{2} \alpha+\cos ^{2} \beta+\cos ^{2} \gamma=1$
Proof: Let

$$
\begin{aligned}
& r=[x, y, z]=x i+y j+z k \\
& \therefore \quad|r|=\sqrt{x^{2}+y^{2}+z^{2}}=r
\end{aligned}
$$

[Image removed]
then $\frac{r}{|r|}=\left[\frac{x}{r}, \frac{y}{r}, \frac{z}{r}\right]$ is the unit vector in the direction of the vector $\underline{r}=\overrightarrow{O P}$
It can be visualized that the triangle $O A P$ is a right triangle with $m \angle A=90^{\circ}$.
Therefore, in right triangle $O A P$,

$$
\begin{aligned}
& \cos \alpha=\frac{\overrightarrow{O A}}{O P}=\frac{x}{r}, \text { similarly } \\
& \cos \beta=\frac{y}{r}, \cos \gamma=\frac{z}{r}
\end{aligned}
$$

[Image removed]

The numbers $\cos \alpha=\frac{x}{r}, \cos \beta=\frac{y}{r}$ and $\cos \gamma=\frac{z}{r}$ are called the direction cosines of $\overrightarrow{O P}$

$$
\cos ^{2} \alpha+\cos ^{2} \beta+\cos ^{2} \gamma=\frac{x^{2}}{r^{2}}+\frac{y^{2}}{r^{2}}+\frac{z^{2}}{r^{2}}=\frac{x^{2}+y^{2}+z^{2}}{r^{2}}=\frac{r^{2}}{r^{2}}=1
$$

## EXERCISE 14.1

1. Let $\underline{u}=3 \underline{i}+2 \underline{j}-5 \underline{k} \underline{y}=\underline{i}-5 \underline{j}-\underline{k}$ and $w=-4 \underline{i}-\underline{j}+7 \underline{k}$. Find the following:
(i) $\underline{u}+2 \underline{v}+\underline{w}$
(ii) $\underline{v}-3 \underline{w}$
(iii) $|3 \underline{v}+\underline{w}|$.
2. Find the magnitude of the vector $\underline{v}$ and write the direction cosines of $\underline{v}$.
(i) $\underline{v}=3 \underline{i}-2 \underline{j}+6 \underline{k}$
(ii) $\underline{v}=-4 \underline{i}+4 \underline{j}+2 \underline{k}$
(iii) $\underline{v}=-6 \underline{i}+8 \underline{j}$
3. Find $t$, so that $|2 i+(t-1) j+t k|=\sqrt{13}$
4. Find a unit vector in the direction of $\underline{v}=-i+4 \underline{j}-8 \underline{k}$
5. If $\underline{u}=2 \underline{i}+\underline{j}-3 \underline{k}, \underline{v}=-\underline{i}+4 \underline{j}+2 \underline{k}$ and $\underline{w}=3 \underline{i}-2 \underline{j}+\underline{k}$, Find a unit vector parallel to $4 \underline{u}-3 \underline{v}+2 \underline{w}$.
6. Find a vector whose
(i) magnitude is 5 and is parallel to $3 \underline{i}+4 \underline{j}-\underline{k}$
(ii) magnitude is 7 and is parallel to $-\underline{i}+\underline{j}+\underline{k}$.

7. If $u=x i+2 j+3 k, v=i+y j-3 k$ and $w=-2 i-3 j$ represent the sides of a triangle. Find the values of $x$ and $y$.
8. The position vectors of the points $A, B, C$ and $D$ are $u=i+2 j+k, v=7 i+8 j+4 k$, $w=-i+k$ and $z=i+2 j+2 k$ respectively. Show that $\overrightarrow{A B}$ is parallel to $\overrightarrow{C D}$.
9. We say that two vectors $v$ and $w$ in space are parallel if there is a scalar $c$ such that $v=c w$. The vectors point in the same direction if $c>0$ and the vectors point in the opposite direction if $c<0$
(a) Find two vectors of length 2 parallel to the vector $v=2 i-4 j+4 k$.
(b) Find the constant $a$ so that the vectors $v=i-3 j+4 k$ and $w=a i+9 j-12 k$ are parallel.
(c) Find a vector of length 5 in the direction opposite that of $v=i-2 j+3 k$.
(d) Find $a$ and $b$ so that the vectors $3 i-j+4 k$ and $a i+b j-2 k$ are parallel.
10. A spacecraft moves from point $(120,240, \rightarrow 50)$ to point $(130,210,80)$ in kilometres. What is the magnitude of the displacement vector in kilometres?
11. Find the direction cosines for the given vector:
(i) $u=-6 i+3 j+2 k$
(ii) $v=4 i+2 j-5 k$
(iii) $P Q$, where $P(9,3,13)$ and $Q(11,6,19)$.
12. Which of the following triple can be the direction angles of a single vector?
(i) $45^{\circ}, 45^{\circ}, 60^{\circ}$
(ii) $30^{\circ}, 45^{\circ}, 60^{\circ}$
(iii) $45^{\circ}, 60^{\circ}, 60^{\circ}$

Product of Two Vectors: Multiplication of two vectors is an important algebraic operation in vector algebra. This algebraic operation plays a fundamental role for understanding various physical and mathematical real-life situation. Unlike the multiplication of numbers, product of vector can be performed in two distinct ways. The two primary types of vector multiplication are the dot product and the cross product. The dot product is a scalar number while cross product is a vector quantity.

# 14.2 Dot or Scalar Product 

14.2.1 Dot or Scalax Product of Two Vectors and Its Geometrical Interpretation We shall now consider products of two vectors that originated in the study of physics and engineering. The concept of angle between two vectors is expressed in terms of a scalar product of two vectors.

Definition 1: Let two non-zero vectors $\underline{u}$ and $\underline{v}$, in the plane or in space, have same initial point. The dot product of $\underline{u}$ and $\underline{v}$, written as $\underline{u} \cdot \underline{v}$, is defined by

$$
\underline{u} \cdot \underline{v}=|\underline{u}||\underline{v}| \cos 0
$$

[Image removed]
[Image removed]
[Image removed]

Where $\theta$ in the angle between $\underline{u}$ and $\underline{v}$ and $0 \leq \theta \leq \pi$

# Definition 2: 

(a) If $\underline{u}=a_{1} \underline{i}+\underline{b}_{1} \underline{j}$ and $\underline{v}=a_{2} \underline{i}+\underline{b}_{2} \underline{j}$ are two non-zero vectors in the plane. The dot product $\underline{u} \cdot \underline{v}$ is defined by:

$$
\underline{u} \cdot \underline{v}=a_{1} a_{2}+b_{1} b_{2}
$$

(b) If $\underline{u}=a_{1} \underline{i}+\underline{b}_{1} \underline{j}+\underline{c}_{1} \underline{k}$ and $\underline{v}=a_{2} \underline{i}+\underline{b}_{2} \underline{j}+\underline{c}_{2} \underline{k}$ are two non-zero vectors in space. The dot product $\underline{u} \cdot \underline{v}$ is defined by

$$
\underline{u} \cdot \underline{v}=a_{1} a_{2}+b_{1} b_{2}+c_{1} c_{2}
$$

Note The dot product is also referred as the scalar product or the inner product.
Example 5 Prove the equivalence of above two definitions of dot product of two vectors:
(i) If $\underline{v}=\left[x_{1}, y_{1}\right]$ and $\underline{w}=\left[x_{2}, y_{2}\right]$ are two vectors in the plane, then $\underline{v} \underline{w}=x_{1} x_{2}+y_{1} y_{2}$
(ii) If $\underline{v}$ and $\underline{w}$ are two non-zero vectors in the plane, then $\underline{v} \cdot \underline{w}=|\underline{v}||\underline{w}| \cos \theta$, where $\theta$ is the angle between $\underline{v}$ and $\underline{w}$ and $0 \leq \theta \leq \pi$.
Proof: Let $\underline{v}$ and $\underline{w}$ be the sides of a triangle then the third side opposite to the angle $\theta$, has length $|\underline{v}-\underline{w}|$ By law of cosines,

$$
\begin{aligned}
|\underline{v}-\underline{w}|^{2} & =|\underline{v}|^{2}+|\underline{w}|^{2}-2|\underline{v}||\underline{w}| \cos \theta \\
\text { if } \quad \underline{v} & =\left[x_{1}, y_{1}\right] \text { and } \underline{w}=\left[x_{2}, y_{2}\right] \text {, then } \\
\underline{v}-\underline{w} & =\left[x_{1}-x_{2}, y_{1}-y_{2}\right]
\end{aligned}
$$

[Image removed]

The law of cosine: $a^{2}=b^{2}+c^{2}-2 b c \cos a$

So, equation (1) becomes:

$$
\begin{aligned}
& \left(x_{1}-x_{2}\right)^{2}+\left(y_{1}-y_{2}\right)^{2}=x_{1}^{2}+y_{1}^{2}+x_{2}^{2}+y_{2}^{2}-2|\underline{v}||\underline{w}| \cos \theta \\
& -2 x_{1} x_{2}-2 y_{1} y_{2}=-2|\underline{v}||\underline{w}| \cos \theta \\
& x_{1} x_{2}+y_{1} y_{2}=|\underline{v}||\underline{w}| \cos \theta=\underline{v} \cdot \underline{w}
\end{aligned}
$$

# 14.2.2 Deduction of the Important Results 

By applying the definition of dot product to unit vectors $i, j$ and $k$, we have
(a) $i . i=|i| i \mid \cos 0^{\circ}=1$
$j . j=|j||j \cos 0^{\circ}=1$
$k . k=|k||k \cos 0^{\circ}=1$
(b) $i . j=|i||j \cos 90^{\circ}=0$
$j . k=|j||k \cos 90^{\circ}=0$
$k . i=|k||i \cos 90^{\circ}=0$

### 14.2.3 Projection of a Vector along Another Vector

In many physical applications, it is required to know "how much" of a vector is applied along a given direction. For this purpose, we find the projection of one vector along the other vector.
Let $\overrightarrow{O A}=\underline{u}$ and $\overrightarrow{O B}=\underline{v}$
Let $\theta$ be the angle between them, such that $0 \leq \theta \leq \pi$.
Draw $\overrightarrow{B M} \perp \overrightarrow{O A}$. Then $\overrightarrow{O M}$ is called the projection of $\underline{v}$ along $\underline{u}$.
From the figure: $\frac{\overrightarrow{O M}}{\overrightarrow{O B}}=\cos \theta$, that is,

$$
\overrightarrow{O M}=|\overrightarrow{O B}| \cos \theta=|\underline{v}| \cos \theta
$$

[Image removed]

Now, $u \cdot \underline{v}=|\underline{u}||\underline{v}| \cos \theta=|\underline{u}|(|\underline{v}| \cos \theta)=|\underline{u}|(\overrightarrow{O M})$
$=$ (magnitude of $\underline{u}$ ). (projection of $\underline{v}$ along $\underline{u}$ )
Thus, geometrically, the dot product of two vectors represents the product of the magnitude of one vector and the projection of the other vector onto it. In other words, the dot product of two vectors shows how much one vector extends in the direction of another.

Now, by definition, $\quad \cos \theta=\frac{u \cdot v}{|\underline{u}||\underline{v}|}$
From (1) and (2),

$$
\overrightarrow{O M}=|\underline{v}| \cdot \frac{u \cdot \underline{v}}{|\underline{u}||\underline{v}|}=\frac{u \cdot \underline{v}}{|\underline{u}|}
$$

$\therefore \quad$ Projection of $\underline{v}$ along $\underline{u}=\frac{\underline{u} \cdot \underline{v}}{|\underline{u}|}$
Similarly, projection of $\underline{u}$ along $\underline{v}=\frac{\underline{u} \cdot \underline{v}}{|\underline{v}|}$

# 14.2.4 Properties of Dot Product 

Let $\underline{u}, \underline{v}$ and $\underline{w}$ be vectors and let $c$ be any real number, then
(i) $\underline{u} \cdot \underline{v}=0 \Rightarrow \underline{u}=0$ or $\underline{v}=0$ or $\underline{u} \perp \underline{v}$
(ii) $\underline{u} \cdot \underline{v}=\underline{v} \cdot \underline{u} \quad$ (Commutative property)
(iii) $\underline{u} \cdot(\underline{v}+\underline{w})=\underline{u} \cdot \underline{v}+\underline{u} \cdot \underline{w} \quad$ (Distributive property)
(iv) $(c \underline{u}) \cdot \underline{v}=c(\underline{u} \cdot \underline{v}) \quad$ (c is scalar)
(v) $\underline{u} \cdot \underline{u}=|\underline{u}|^{2}$

### 14.2.5 Dot Product of Vectors in terms of their components

Let $\underline{u}=a_{1} \underline{i}+b_{1} \underline{j}+c_{1} \underline{k}$ and $\underline{v}=a_{2} \underline{i}+b_{2} \underline{j}+c_{2} \underline{k}$ be two non-zero vectors.
From distributive law we can write:

$$
\begin{aligned}
\therefore \quad \underline{u} \cdot \underline{v}= & \left(a_{1} i+b_{1} \underline{j}+c_{1} \underline{k}\right) \cdot\left(a_{2} i+b_{2} \underline{j}+c_{2} \underline{k}\right) \\
= & a_{1} a_{2}(i \cdot i)+a_{1} b_{2}(i \cdot j)+a_{1} c_{2}(i \cdot k)+b_{1} a_{2}(j \cdot i)+b_{1} b_{2}(j \cdot j)+b_{1} c_{2}(j \cdot k) \\
& +c_{1} a_{2}(k \cdot i)+c_{1} b_{2}(k \cdot j)+c_{1} c_{2}(k \cdot k) \\
\Rightarrow \quad \underline{u} \cdot \underline{v}= & a_{1} a_{2}+b_{1} b_{2}+c_{1} c_{2} \quad \because i \cdot i=\underline{j} \cdot \underline{j}=\underline{k} \cdot \underline{k}=1 \\
& i \cdot j=\underline{j} \cdot \underline{k}=\underline{k} \cdot \underline{i}=0
\end{aligned}
$$

Hence the dot product of two vectors is the sum of the product of their corresponding components.
Example 6 Show that the components of a vector are the projections of that vector along $i, j$ and $k$ respectively.
Proof: Let $\underline{v}=a \underline{i}+b \underline{j}+c \underline{k}$, then
Projection of $\underline{v}$ along $\underline{i}=\frac{\underline{v} \cdot \underline{i}}{|\underline{i}|}=(a \underline{i}+b \underline{j}+c \underline{k}) \cdot \underline{i}=a$
Projection of $\underline{v}$ along $\underline{j}=\frac{\underline{v} \cdot \underline{j}}{|\underline{j}|}=(a \underline{i}+b \underline{j}+c \underline{k}) \cdot \underline{j}=b$
Projection of $\underline{v}$ along $\underline{k}=\frac{\underline{v} \cdot \underline{k}}{|\underline{k}|}=(a \underline{i}+b \underline{j}+c \underline{k}) \cdot \underline{k}=c$
Hence components $a, b$ and $c$ of vector $\underline{v}=a \underline{i}+b \underline{j}+c \underline{k}$ are projections of vector $\underline{v}$ along $i, j$ and $k$ respectively.

Example 7 Prove that in any triangle $A B C$
(i) $\quad a^{2}=b^{2}+c^{2}-2 b c \cos A$
(ii) $\quad a=b \cos C+c \cos B$
(Cosine Law)
(Projection Law)
Proof: Let the vectors $\underline{a}, \underline{b}$ and $\underline{c}$ be along the sides $B C, C A$ and $A B$ of the triangle $A B C$ as shown in the figure.
(i) $\underline{a}+\underline{b}+\underline{c}=\underline{0}$
$\Rightarrow \quad \underline{a}=-(\underline{b}+\underline{c})$
Now $\quad \underline{a} \cdot \underline{a}=(\underline{b}+\underline{c}) \cdot(\underline{b}+\underline{c})$
$\Rightarrow \quad=\underline{b} \cdot \underline{b}+\underline{b} \cdot \underline{c}+\underline{c} \cdot \underline{b}+\underline{c} \cdot \underline{c}$
$\Rightarrow \quad a^{2}=b^{2}+2 \underline{b} \cdot \underline{c}+c^{2} \quad(\because \underline{b} \cdot \underline{c}=\underline{c} \cdot \underline{b})$
$\Rightarrow \quad a^{2}=b^{2}+c^{2}+2 b c \cos (\pi-A)$
$\therefore \quad a^{2}=b^{2}+c^{2}-2 b c \cos A$
(ii) $\underline{a}+\underline{b}+\underline{c}=\underline{0}$
$\Rightarrow \quad \underline{a}=-\underline{b}-\underline{c}$
Take dot product with $\underline{a}$

$$
\begin{aligned}
\underline{a} \cdot \underline{a} & =-\underline{a} \cdot \underline{b}-\underline{a} \cdot \underline{c} \\
& =-a b \cos (\pi-C)-a c \cos (\pi-B) \\
& =-a b(-\cos C)-a c(-\cos B) \\
a^{2} & =a b \cos C+a c \cos B \\
\Rightarrow \quad a & =b \cos C+c \cos B
\end{aligned}
$$

Example 8 Prove that: $\cos (\alpha-\beta)=\cos \alpha \cos \beta+\sin \alpha \sin \beta$
Proof: Let $\overrightarrow{O A}$ and $\overrightarrow{O B}$ be the unit vectors in the $x y$-plane making angles $\alpha$ and $\beta$ with the positive $x$-axis.
So that $m \angle A O B=\alpha-\beta$
Now $\overrightarrow{O A}=\cos \alpha \underline{i}+\sin \alpha \underline{j}$
and $\overrightarrow{O B}=\cos \beta \underline{i}+\sin \beta \underline{j}$
$\therefore \quad \overrightarrow{O A} \cdot \overrightarrow{O B}=(\cos \alpha \underline{i}+\sin \alpha \underline{j}) \cdot(\cos \beta \underline{i}+\sin \beta \underline{j})$
$\Rightarrow|\overrightarrow{O A}||\overrightarrow{O B}| \cos (\alpha-\beta)=\cos \alpha \cos \beta+\sin \alpha \sin \beta$
$\therefore \quad \cos (\alpha-\beta)=\cos \alpha \cos \beta+\sin \alpha \sin \beta$
[Image removed]
$(\because|\overrightarrow{O A}|=|\overrightarrow{O B}|=1)$

# 14.2.6 Orthogonality of Two Vectors 

Definition: Two non-zero vectors $\underline{u}$ and $\underline{v}$ are orthogonal (perpendicular) if and only if $\underline{u} \cdot \underline{v}=0$.
The dot product of two vectors $\underline{u}$ and $\underline{v}$ becomes zero when $\underline{u} \perp \underline{v}, \theta=90^{\circ}$ or $\frac{\pi}{2}$ radius.

$$
\underline{u} \cdot \underline{v}=|\underline{u}| \perp|\underline{v}| \cos 90^{\circ}=0
$$

Note:
The zero vector $\underline{o}$ is orthogonal to every vector because:

$$
\underline{o} \cdot \underline{b}=0 \forall \underline{b}
$$

Thus, $\underline{u} \cdot \underline{v}=0 \Leftrightarrow \underline{u} \perp \underline{v}$
Example 9 If $\underline{u}=3 \underline{i}-j-2 \underline{k}$ and $\underline{v}=i+2 j-\underline{k}$, then find $\underline{u} \cdot \underline{v}$.
Solution $\underline{u} \cdot \underline{v}=(3)(1)+(-1)(2)+(-2)(-1)=3$
Example 10 If $\underline{u}=2 \underline{i}-4 \underline{j}+5 \underline{k}$ and $\underline{v}=4 \underline{i}-3 \underline{j}-4 \underline{k}$, then prove that $\underline{u}$ and $\underline{v}$ are orthogonal.
Solution $\underline{u} \cdot \underline{v}=(2)(4)+(-4)(-3)+(5)(-4)=0$
$\Rightarrow \quad \underline{u}$ and $\underline{v}$ are perpendicular
Example 11 Find a scalar $a$ so that the vectors $2 \underline{i}+\alpha \underline{j}+5 \underline{k}$ and $3 \underline{i}+\underline{j}+\alpha \underline{k}$ are orthogonal.
Solution Let $\underline{u}=2 \underline{i}+\alpha \underline{j}+5 \underline{k}$ and $\underline{v}=3 \underline{i}+\underline{j}+\alpha \underline{k}$
It is given that $\underline{u}$ and $\underline{v}$ are orthogonal

$$
\begin{aligned}
& \therefore \quad \underline{u} \cdot \underline{v} \\
& \Rightarrow \quad(2 \underline{i}+\alpha \underline{j}+5 \underline{k}) \cdot(3 \underline{i}+\underline{j}+\alpha \underline{k})=0 \\
& \Rightarrow \quad 6+\alpha+5 \alpha=0 \\
& \quad \therefore \quad \alpha=-1
\end{aligned}
$$

### 14.2.7 Angle Between Two Vectors

The angle between two vectors $\underline{u}$ and $\underline{v}$ is determined from the definition of dot product, that is
(a) $\underline{u} \cdot \underline{v}=|\underline{u}||\underline{v}| \cos 0, \quad$ where $0 \leq \theta \leq \pi$

$$
\Rightarrow \quad \cos \theta=\frac{\underline{u} \cdot \underline{v}}{|\underline{u}||\underline{v}|}
$$

(b) If $\underline{u}=a_{1} \underline{i}+\underline{b}_{1} \underline{j}+\underline{c}_{1} \underline{k} \quad$ and $\quad \underline{v}=\underline{a}_{2} \underline{i}+\underline{b}_{2} \underline{j}+\underline{c}_{2} \underline{k}$, then

$$
\begin{aligned}
\underline{u} \cdot \underline{v} & =a_{1} a_{2}+b_{1} b_{2}+c_{1} c_{2} \\
|\underline{u}| & =\sqrt{a_{1}^{2}+b_{1}^{2}+c_{1}^{2}} \quad \text { and } \quad|\underline{v}|=\sqrt{a_{2}^{2}+b_{2}^{2}+c_{2}^{2}}
\end{aligned}
$$

$$
\begin{aligned}
& \therefore \quad \cos \theta=\frac{u \cdot \psi}{|u||v|} \\
& \therefore \quad \cos \theta=\frac{a_{1} a_{2}+b_{1} b_{2}+c_{1} c_{2}}{\sqrt{a_{1}^{2}+b_{1}^{2}+c_{1}^{2}} \sqrt{a_{2}^{2}+b_{2}^{2}+c_{2}^{2}}}
\end{aligned}
$$

Example 12 Find the angle between the vectors.

$$
u=2 i-j+k \quad \text { and } \quad v=-i+j
$$

Solution $u \cdot v=(2 i-j+k) \cdot(-i+j+0 k)$

$$
=(2)(-1)+(-1)(1)+(1)(0)=-3
$$

and

$$
\begin{aligned}
|\underline{u}| & =|2 i-j+k|=\sqrt{(2)^{2}+(-1)^{2}+(1)^{2}}=\sqrt{6} \\
|\underline{v}| & =|-i+j+0 k|=\sqrt{(-1)^{2}+(1)^{2}+(0)^{2}}=\sqrt{2}
\end{aligned}
$$

Now $\cos \theta=\frac{u \cdot \psi}{|u| \cdot|v|}$
$\Rightarrow \quad \cos \theta=\frac{-3}{\sqrt{6} \cdot \sqrt{2}}$

$$
=-\frac{\sqrt{3}}{2}
$$

$$
\therefore \quad 0=\frac{5 \pi}{6}
$$

Example 13 Show that the vectors $\overrightarrow{A B}=2 i-j+k, \overrightarrow{B C}=i-3 j-5 k$ and $\overrightarrow{A C}=3 i-4 j-4 k$ are the sides of a right triangle.
Solution Given $\overrightarrow{A B}=2 i-j+k, \overrightarrow{B C}=i-3 j-5 k$ and

$$
\overrightarrow{A C}=3 i-4 j-4 k
$$

Now

$$
\begin{aligned}
\overrightarrow{A B}+\overrightarrow{B C} & =(2 i-j+k)+(i-3 j-5 k) \\
& =3 i-4 j-4 k=\overrightarrow{A C} \text { (third side) }
\end{aligned}
$$

$\therefore \quad \overrightarrow{A B}, \overrightarrow{B C}$ and $\overrightarrow{A C}$ form a triangle $A B C$.
Further we prove that $\triangle A B C$ is a right triangle

$$
\begin{aligned}
\overrightarrow{A B} \cdot \overrightarrow{B C} & =(2 i-j+k) \cdot(i-3 j-5 k) \\
& =(2)(1)+(-1)(-3)+(1)(-5)=2+3-5=0 \\
\therefore \quad \overrightarrow{A B} \perp \overrightarrow{B C} & \\
& \text { Hence, } \triangle A B C \text { is a right triangle. }
\end{aligned}
$$

# 14.2.8 Work Done By a Constant Force 

If a constant force $F$, applied to a body, acts at an angle $\theta$ to the direction of motion, then the work done by $\underline{F}$ is defined to be the product of the component of $\underline{F}$ in the direction of the displacement and the distance that the body moves.
In figure, a constant force $\underline{F}$ acting on a body, displaces it from $A$ to $B$.
$\therefore \quad$ Work done $=($ component of $\underline{F}$ along $A B)$ (displacement)

$$
=(F \cos \theta)(A B)=\underline{F} \cdot \underline{A B}=\underline{F} \cdot \underline{d}
$$

Example 14 The constant forces $2 i+5 j+6 k$ and $-i-2 j-k$ act on a body displaced from position $P(4,-3,-2)$ to $Q(6,1,-3)$. Find the total work done.
Solution
Total force $=(2 i+5 j+6 k)+(-i-2 j-k)$

$$
\Rightarrow \quad \underline{F}=i+3 j+5 k
$$

The displacement of the body $=P \vec{Q}=(6-4) i+(1+3) j+(-3+2) k$

$$
\Rightarrow \quad \underline{d}=2 i+4 j-k
$$

$\therefore \quad$ Work done $=\underline{F} \cdot \underline{d}$

$$
=(i+3 j+5 k) \cdot(2 i+4 j-k)=2+12-5=9 \text { units }
$$

## EXERCISE 14.2

1. Find the coahues of the angle $\theta$ between $\underline{u}$ and $\underline{v}$ :
(i) $\underline{u}=2 i+3 j+k, \underline{v}=-i+2 j+2 k$
(ii) $\underline{u}=[-3,2,5], \underline{v}=[1,6,-2]$
2. If $a+b+c=0$ and $|a|=3,|b|=5$ and $|c|=7$. Find the angle between $a$ and $b$.
3. If $|a|=3,|b|=4$ and $|a+b|=5$. Find the angle between $a$ and $b$.
4. Calculate the projection of $a$ along $b$ and projection of $b$ along $a$ when:
(i) $a=2 i+3 j-k, b=i-2 j+4 k$ (ii) $a=4 i-2 j+3 k, b=i+j+k$
5. Find a real number $a$ so that the vectors $u$ and $v$ are perpendicular:
(i) $\underline{u}=\alpha i+3 j+k, \underline{v}=i-2 j+\alpha k$ (ii) $\underline{u}=\alpha i+2 \alpha j-k, \underline{v}=i+\alpha j+3 k$
6. Find the number $z$ so that the triangle with vertices $A(3,0,-2), B(0,3,1)$ and $C(1,1, z)$ is a right triangle with right angle at $C$.

7. If $\hat{a}$ and $\hat{b}$ are unit vectors and $2 \theta$ is the angle between them, show that $\sin \theta=\frac{1}{2}|\hat{a}-\hat{b}|$.
8. If $|a+b|=|a-b|$, then show that $a$ and $b$ are perpendicular.
9. (i) Show that the vectors $3 i-2 j+k, i-3 j+5 k$ and $2 i+j-4 k$ form a right triangle.
(ii) Show that the set of points $P(4,-1,2), Q(1,3,-1)$ and $R(-2,4,6)$ form a right triangle.
10. Prove that the $\cos (\alpha+\beta)=\cos \alpha \cos \beta-\sin \alpha \sin \beta$
11. Prove that in any triangle $A B C$.
(i) $b=c \cos A+a \cos C$
(ii) $c=a \cos B+b \cos A$
(iii) $b^{2}=c^{2}+a^{2}-2 c a \cos B$
(iv) $c^{2}=a^{2}+b^{2}-2 a b \cos C$
12. Show that for any vectors $a$ and $b, \quad|a|-|b| \leq|a+b| \leq|a|+|b|$
13. Find the work done, if the point at which the constant force $F=2 i+5 j+3 k$ is applied to an object, moves it from $P_{1}(2,-3,1)$ to $P_{2}(7,5,3)$.
14. A particle, acted by constant forces $F_{1}=3 i+4 j-3 k$ and $F_{2}=i+4 j-k$, is displaced from $A(2,1,3)$ to $B(5,4,4)$. Find the work done.
15. A particle is displaced from the point $A(5,-5,-7)$ to the point $B(6,2,-2)$ under the action of constant forces defined by $10 i-j+11 k, 4 i+5 j+9 k$ and $-2 i+j-9 k$. Show that the total work done by the force is 102 units.
16. A force of magnitude 6 units acting parallel to $4 i+3 j-k$ displace the point of application from $A(2,-1,3)$ to $B(7,3,2)$. Find the work done.

# 14.3 Cross Product or Vector Product 

### 14.3.1 The Cross Product or Vector Product of Two Vectors and its Geometrical Interpretation

One of the key multiplication operations involving vectors in space is the cross product. Unlike the dot product, which results is a scalar, the cross product of two vectors yields a vector quantity. The vector product of two vectors is widely used in Physics, particularly in fields of mechanics and electricity. It is only defined for vectors in space. Let $\underline{u}$ and $\underline{v}$ be two non-zero vectors. The cross or vector product of $\underline{u}$ and $\underline{v}$ gives a

vector that is perpendicular to both the vectors $\underline{u}$ and $\underline{v}$, written as $\underline{u} \times \underline{v}$, is defined by

$$
\underline{u} \times \underline{v}=(\|\underline{u}\| \mid \underline{v} \mid \sin \theta) \underline{n}
$$

where $\theta$ is the angle between the vectors, such that $0 \leq \theta \leq \pi$ and $\underline{n}$ is a unit vector perpendicular to the plane of $\underline{u}$ and $\underline{v}$ with direction given by the right-hand rule.
[Image removed]

Figure (a)
Right hand
Right hand rule
[Image removed]

Figure (b)
(i) If the fingers of the right hand point along the vector $\underline{u}$ and then curl towards the vector $\underline{v}$, then the thumb will give the direction of $\underline{n}$ which is $\underline{u} \times \underline{v}$. It is shown in the figure (a).
(ii) In figure (b), the right hand rule shows the direction of $\underline{v} \times \underline{u}$.

# 14.3.2 Parallel Vectors 

If $\underline{u}$ and $\underline{v}$ are parallel vectors, then $(\theta=0 \Rightarrow \sin 0=0)$.

$$
\begin{aligned}
& \underline{u} \times \underline{v}=\|\underline{u}\| \mid \underline{v}\| \sin \theta \underline{n} \\
& \underline{u} \times \underline{v}=0 \quad \text { or } \quad \mid \underline{u} \times \underline{v}=0
\end{aligned}
$$

And if $\underline{u} \times \underline{v}=0$, then either $\sin \theta=0 \quad$ or $\quad\|\underline{u}\|=0 \quad$ or $\quad\|\underline{v}\|=0$
(i) If $\sin \theta=0 \Rightarrow \theta=0^{\circ}$ or $180^{\circ}$. Which shows that the vectors $\underline{u}$ and $\underline{v}$ are parallel.
(ii) If $\underline{u}=\underline{0}$ or $\underline{v}=\underline{0}$, then since the zero vector has no specific direction, we adopt the convention that the zero vector is parallel to every vector.

## Note: Zero vector is both parallel and perpendicular to every vector. This apparent contradiction will cause no trouble, since the angle between two vectors is never applied when one of them is zero vector.

### 14.3.3 Derivation of Useful Results of Cross Products

By applying the definition of cross product to unit vectors $i, j$ and $k$, we have:
(a) $\underline{i} \times \underline{i}=\|\underline{i}\| \mid i\left\|\sin 0^{\circ} \underline{n}=\underline{0}\right.$
$\underline{j} \times \underline{j}=\|\underline{j}\| \mid \underline{j}\| \sin 0^{\circ} \underline{n}=\underline{0}$
$\underline{k} \times \underline{k}=\|\underline{k}\| \mid \underline{k}\left\|\sin 0^{\circ} \underline{n}=\underline{0}\right.$
[Image removed]

(b) $\quad \underline{i} \times \underline{j}=|\underline{i}||\underline{j}| \sin 90^{\circ} \underline{k}=\underline{k}$

$$
\begin{aligned}
& \underline{j} \times \underline{k}=|\underline{j}||\underline{k}| \sin 90^{\circ} \underline{i}=\underline{i} \\
& \underline{k} \times \underline{i}=|\underline{k}||\underline{i}| \sin 90^{\circ} \underline{j}=\underline{j}
\end{aligned}
$$

(c) $\quad \underline{u} \times \underline{u}=|\underline{u}||\underline{u}| \sin 0 \underline{n}=\underline{0}$

# 14.3.4 Properties of Cross Product 

[Image removed]

The cross product possesses the following properties:
(i) $\underline{u} \times \underline{v}=\underline{0}$ if $\underline{u}=\underline{0}$ or $\underline{v}=\underline{0}$
(ii) $\underline{u} \times \underline{v}=-\underline{v} \times \underline{u}$
(iii) $\underline{u} \times(\underline{v}+\underline{w})=\underline{u} \times \underline{v}+\underline{u} \times \underline{w}$
(iv) $\underline{u} \times(\underline{k} \underline{v})=(\underline{k} \underline{u}) \times \underline{v}=\underline{k}(\underline{u} \times \underline{v})$
(v) $\underline{u} \times \underline{u}=\underline{0}$

The proofs of these properties are left as an exercise for the students.

### 14.3.5 Analytical Expressions of $\underline{u} \times \underline{v}$ (Determinant formula for $\underline{u} \times \underline{v}$ )

Let $\underline{u}=a_{1} \underline{i}+\underline{b}_{1} \underline{j}+\underline{c}_{1} \underline{k}$ and $\underline{v}=a_{2} \underline{i}+\underline{b}_{2} \underline{j}+\underline{c}_{2} \underline{k}$, then

$$
\begin{aligned}
\underline{u} \times \underline{v}= & \left(a_{1} \underline{i}+\underline{b}_{1} \underline{j}+\underline{c}_{1} \underline{k}\right) \times\left(a_{2} \underline{i}+\underline{b}_{2} \underline{j}+\underline{c}_{2} \underline{k}\right) \\
= & a_{1} a_{2}(\underline{i} \times \underline{i})+a_{1} \underline{b}_{2}(\underline{i} \times \underline{j})+a_{1} \underline{c}_{2}(\underline{i} \times \underline{k}) \\
& +\underline{b}_{1} a_{2}(\underline{j} \times \underline{i})+\underline{b}_{1} \underline{b}_{2}(\underline{j} \times \underline{j})+\underline{b}_{1} \underline{c}_{2}(\underline{j} \times \underline{k}) \\
& +\underline{c}_{1} \underline{a}_{2}(\underline{k} \times \underline{i})+\underline{c}_{1} \underline{b}_{2}(\underline{k} \times \underline{j})+\underline{c}_{1} \underline{c}_{2}(\underline{k} \times \underline{k}) \\
& =a_{1} \underline{b}_{2} \underline{k}-a_{1} \underline{c}_{2} \underline{j}-\underline{b}_{1} \underline{a}_{2} \underline{k}+\underline{b}_{1} \underline{c}_{2} \underline{i}+\underline{c}_{1} \underline{a}_{2} \underline{j}-\underline{c}_{1} \underline{b}_{2} \underline{i} \\
\Rightarrow \quad & \underline{u} \times \underline{v}=\left(\underline{b}_{1} \underline{c}_{2}-\underline{c}_{1} \underline{b}_{2}\right) \underline{i}-\left(\underline{a}_{1} \underline{c}_{2}-\underline{c}_{1} \underline{a}_{2}\right) \underline{j}+\left(\underline{a}_{1} \underline{b}_{2}-\underline{b}_{1} \underline{a}_{2}\right) \underline{k}
\end{aligned}
$$

The expression of $3 \times 3$ determinant

$$
=\left|\begin{array}{ccc}
\underline{i} & \underline{i} & \underline{k} \\
a_{1} & \underline{b}_{1} & \underline{c}_{1} \\
a_{2} & \underline{b}_{2} & \underline{c}_{2}
\end{array}\right|=\left(\underline{b}_{1} \underline{c}_{2}-\underline{c}_{1} \underline{b}_{2}\right) \underline{i}-\left(\underline{a}_{1} \underline{c}_{2}-\underline{c}_{1} \underline{a}_{2}\right) \underline{j}+\left(\underline{a}_{1} \underline{b}_{2}-\underline{b}_{1} \underline{a}_{2}\right) \underline{k}
$$

The terms on R.H.S of equation (i) are the same as the terms in the expansion of the above determinant.

$$
\text { Hence } \underline{u} \times \underline{v}=\left|\begin{array}{ccc}
\underline{i} & \underline{j} & \underline{k} \\
a_{1} & \underline{b}_{1} & \underline{c}_{1} \\
a_{2} & \underline{b}_{2} & \underline{c}_{2}
\end{array}\right|
$$

which is known as determinant formula for $\underline{u} \times \underline{v}$.

# Unit 44 Vectors in Space 

Note The expression on R.H.S. of equation (ii) is not an actual determinant, since its entries are not all scalars. It is simply a way of remembering the complicated expression on R.H.S of equation (i).

Example 15 Find a vector perpendicular to each of the vectors. Also verify that $\underline{a}$ and $\underline{b}$ are $\perp$ to $\underline{a} \times \underline{b}$

$$
\underline{a}=2 \underline{i}-\underline{j}+\underline{k} \quad \text { and } \quad \underline{b}=4 \underline{i}+2 \underline{j}-\underline{k}
$$

Solution A vector perpendicular to both the vectors $\underline{a}$ and $\underline{b}$ is $\underline{a} \times \underline{b}$.

$$
\therefore \quad \underline{a} \times \underline{b}=\left|\begin{array}{ccc}
\underline{i} & \underline{j} & \underline{k} \\
2 & -1 & 1 \\
4 & 2 & -1
\end{array}\right|=-i+6 j+8 k
$$

Verification:

$$
\begin{gathered}
\underline{a} \cdot \underline{a} \times \underline{b}=(2 \underline{i}-\underline{j}+\underline{k}) \cdot(-i+6 \underline{j}+8 \underline{k})=(2)(-1)+(-1)(6)+(1)(8)=0 \\
\text { and } \quad \underline{b} \cdot \underline{a} \times \underline{b}=(4 \underline{i}+2 \underline{j}-\underline{k}) \cdot(-i+6 \underline{j}+8 \underline{k})=(4)(-1)+(2)(6)+(-1)(8)=0
\end{gathered}
$$

Hence $\underline{a} \times \underline{b}$ is perpendicular to both the vectors $\underline{a}$ and $\underline{b}$.

### 14.3.6 Angle Between Two Vectors (Cross Product)

The sine of the angle between two vectors $\underline{a}$ and $\underline{b}$ is determined from the definition of cross product.
If $\theta$ is the sine of the angle between $\underline{a}$ and $\underline{b}$, then $|\underline{a} \times \underline{b}|=|\underline{a}||\underline{b}| \sin \theta$

$$
\Rightarrow \quad \sin \theta=\frac{|\underline{a} \times \underline{b}|}{|\underline{a}||\underline{b}|}
$$

Example 16 If $\underline{a}=4 \underline{i}+3 \underline{j}+\underline{k}$ and $\underline{b}=2 \underline{i}-\underline{j}+2 \underline{k}$. Find a unit vector perpendicular to both $\underline{a}$ and $\underline{b}$. Also find the sine of the angle between the vectors $\underline{a}$ and $\underline{b}$.

Solution

$$
\begin{aligned}
& \underline{a} \times \underline{b}=\left|\begin{array}{ccc}
\underline{i} & \underline{j} & \underline{k} \\
4 & 3 & 1 \\
2 & -1 & 2
\end{array}\right|=7 \underline{i}-6 \underline{j}-10 \underline{k} \\
& \text { and } \quad|\underline{a} \times \underline{b}|=\sqrt{(7)^{2}+(-6)^{2}+(-10)^{2}}=\sqrt{185} \\
& \therefore \quad \text { A unit vector perpendicular to } \underline{a} \text { and } \underline{b}=\frac{\underline{a} \times \underline{b}}{|\underline{a} \times \underline{b}|}=\frac{7 \underline{i}-\underline{b} \underline{j}-10 \underline{k}}{\sqrt{185}} \\
& \text { Now } \quad|\underline{a}|=\sqrt{(4)^{2}+(3)^{2}+(1)^{2}}=\sqrt{26} \\
& \left\lvert\, \underline{b}\right|=\sqrt{(2)^{2}+(-1)^{2}+(2)^{2}}=3
\end{aligned}
$$

If $\theta$ is the angle between $\underline{a}$ and $\underline{b}$, then $|\underline{a} \times \underline{b}|=|\underline{a}||\underline{b}| \sin \theta$

$$
\Rightarrow \quad \sin \theta=\frac{|\underline{a} \times \underline{b}|}{|\underline{a}||\underline{b}|}=\frac{\sqrt{185}}{3 \sqrt{26}}
$$

Example17 Prove that $\sin (\alpha+\beta)=\sin \alpha \cos \beta+\cos \alpha \sin \beta$
Proof: Let $\overrightarrow{O A}$ and $\overrightarrow{O B}$ be two unit vectors in the $x y$-plane making angles $\alpha$ and $-\beta$ with the positive $x$-axis respectively.

So that $m \angle A O B=\alpha+\beta$
Now $\quad \overrightarrow{O A}=\cos \alpha i+\sin \alpha j$
and

$$
\begin{aligned}
\overrightarrow{O B} & =\cos (-\beta) i+\sin (-\beta) j \\
& =\cos \beta i-\sin \beta j \\
\therefore \quad \overrightarrow{O B} \times \overrightarrow{O A} & =(\cos \beta i-\sin \beta j) \times(\cos \alpha i+\sin \alpha i) \\
\Rightarrow \quad & \left|\overrightarrow{O B}\right||\overrightarrow{O A}| \sin (\alpha+\beta) k=\left|\begin{array}{ccc}
i & j & k \\
\cos \beta & -\sin \beta & 0 \\
\cos \alpha & \sin \alpha & 0
\end{array}\right| \\
\Rightarrow \quad & \sin (\alpha+\beta) k=(\sin \alpha \cos \beta+\cos \alpha \sin \beta) k
\end{aligned}
$$

[Image removed]
$\therefore \quad \sin (\alpha+\beta)=\sin \alpha \cos \beta+\cos \alpha \sin \beta$
Example11: In any triangle $A B C$, prove that

$$
\frac{a}{\sin A}=\frac{b}{\sin B}=\frac{c}{\sin C} \text { (Law of Sines) }
$$

Proof: Suppose vectors $\underline{a}, \underline{b}$ and $\underline{c}$ are along the sides $B C, C A$ and $A B$ respectively of the triangle $A B C$.

$$
\begin{aligned}
& \therefore \quad \underline{a}+\underline{b}+\underline{c}=0 \\
& \Rightarrow \quad \underline{b}+\underline{c}=-\underline{a}
\end{aligned}
$$

Take cross product with $\underline{c}$

$$
\begin{aligned}
& \underline{b} \times \underline{c}+\underline{c} \times \underline{c}=-a \times \underline{c} \\
& \underline{b} \times \underline{c}=\underline{c} \times \underline{a} \quad(\because \underline{c} \times \underline{c}=0) \\
& \Rightarrow \quad|\underline{b} \times \underline{c}|=|\underline{c} \times \underline{a}| \\
& \begin{array}{l}
|\underline{b}||\underline{c}| \sin (\pi-A)=|\underline{c}||\underline{a}| \sin (\pi-B) \\
\Rightarrow \quad b c \sin A=c a \sin B \Rightarrow b \sin A=a \sin B
\end{array} \\
& \therefore \quad \frac{b}{\sin B}=\frac{a}{\sin A}
\end{aligned}
$$

[Image removed]

Similarly, by taking cross product of (i) with $\underline{b}$, we have

$$
\frac{a}{\sin A}=\frac{c}{\sin C}
$$

From (ii) and (iii), we get $\frac{a}{\sin A}=\frac{b}{\sin B}=\frac{c}{\sin C}$
Example 19 If $\underline{u}=2 \underline{i}-\underline{j}+\underline{k}$ and $\underline{v}=4 \underline{i}+2 \underline{j}-\underline{k}$, find by determinant formula
(i) $\underline{u} \times \underline{u}$
(ii) $\underline{u} \times \underline{v}$
(iii) $\underline{v} \times \underline{u}$

Solution $\underline{u}=2 \underline{i}-\underline{j}+\underline{k}$ and $\underline{v}=4 \underline{i}+2 \underline{j}-\underline{k}$
By determinant formula
(i) $\quad \underline{u} \times \underline{u}=\left|\begin{array}{ccc}\underline{i} & \underline{j} & \underline{k} \\ 2 & -1 & 1 \\ 2 & -1 & 1\end{array}\right|=0 \quad$ ( $\therefore$ Two rows are same)
(ii) $\quad \underline{u} \times \underline{v}=\left|\begin{array}{ccc}\underline{i} & \underline{j} & \underline{k} \\ 2 & -1 & 1 \\ 4 & 2 & -1\end{array}\right|=(1-2) \underline{i}-(-2-4) \underline{j}+(4+4) \underline{k}=-\underline{i}+6 \underline{j}+8 \underline{k}$
(iii) $\underline{v} \times \underline{u}=\left|\begin{array}{ccc}\underline{i} & \underline{j} & \underline{k} \\ 4 & 2 & -1 \\ 2 & -1 & -1\end{array}\right|=(2-1) \underline{i}-(4+2) \underline{j}+(-4-4) \underline{k}=\underline{i}-6 \underline{j}-8 \underline{k}$

# 14.3.7 Real World Applications on Cross or Vector Product 

(a) Area of Parallelogram

Suppose $\underline{u}$ and $\underline{v}$ are two non-zero vectors and $\theta$ is the angle between them, and suppose that $|\underline{u}|$ and $|\underline{v}|$ represent the length of the adjacent sides of a parallelogram, (see figure). We know that:
[Image removed]

Area of parallelogram $=$ Base $\times$ Height

$$
=(\text { Base })(h)=|\underline{u}||\underline{v}| \sin \theta
$$

$\therefore$ Area of parallelogram $=|\underline{u} \times \underline{v}|$

(b) Area of Triangle

From figure it is clear that
Area of triangle $=\frac{1}{2}$ (Area of parallelogram)
Area of triangle $=\frac{1}{2}|u \times v|$
[Image removed]
where $\underline{u}$ and $\underline{v}$ are vectors along two adjacent sides of the triangle.
Example 20 Find area of the parallelogram whose vertices are $P(0,0,0), Q(-1,2,4), R(2,-1,4)$ and $S(1,1,8)$.
Solution Area of parallelogram $=|\overrightarrow{P Q} \times \overrightarrow{P R}|$
Where $|\overrightarrow{P Q}|$ and $|\overrightarrow{P R}|$ are two adjacent sides of the parallelogram

$$
\begin{aligned}
& \overrightarrow{P Q}=\overrightarrow{O Q}-\overrightarrow{O P}=(-1-0) \underline{i}+(2-0) \underline{j}+(4-0) \underline{k}=-\underline{i}+2 \underline{j}+4 \underline{k} \\
& \overrightarrow{P R}=\overrightarrow{O R}-\overrightarrow{O P}=(2-0) \underline{i}+(-1-0) \underline{j}+(4-0) \underline{k}=2 \underline{i}-\underline{j}+4 \underline{k} \\
& \text { Now } \quad \overrightarrow{P Q} \times \overrightarrow{P R}=\left|\begin{array}{ccc}
\underline{i} & \underline{j} & \underline{k} \\
-1 & 2 & 4 \\
2 & -1 & 4
\end{array}\right|=(8+4) i-(-4-8) j+(1-4) k \\
& =12 i+12 j-3 k
\end{aligned}
$$

$\therefore$ Area of parallelogram $=|\overrightarrow{P Q} \times \overrightarrow{P R}|=|12 i+12 j-3 k|$

$$
=\sqrt{144+144+9}=\sqrt{297} \text { square units }
$$

Example 21 Find the area of the triangle with vertices $A(1,-1,1), B(2,1,-1)$ and $C(-1,1,2)$. Also find a unit vector perpendicular to the plane of triangle $A B C$.
Solution $\overrightarrow{A B}=\overrightarrow{O B}-\overrightarrow{O A}=(2-1) \underline{i}+(1+1) \underline{j}+(-1-1) \underline{k}=\underline{i}+2 \underline{j}-2 \underline{k}$

$$
\begin{aligned}
\overrightarrow{A C} & =\overrightarrow{O C}-\overrightarrow{O A}=(-1-1) \underline{i}+(1+1) \underline{j}+(2-1) \underline{k}=-2 \underline{i}+2 \underline{j}+\underline{k} \\
\overrightarrow{A B} \times \overrightarrow{A C} & =\left|\begin{array}{ccc}
i & j & k \\
1 & 2 & -2 \\
-2 & 2 & 1
\end{array}\right|=(2+4) i-(1-4) j+(2+4) k=6 i+3 j+6 k
\end{aligned}
$$

The area of the parallelogram with adjacent sides $|\overrightarrow{A B}|$ and $|\overrightarrow{A C}|$ and is given by

$$
|\overrightarrow{A B} \times \overrightarrow{A C}|=|6 i+3 j+6 k|=\sqrt{36+9+36}=\sqrt{81}=9
$$

$\therefore \quad$ Area of triangle $=\frac{1}{2}|\overrightarrow{A B} \times \overrightarrow{A C}|=\frac{1}{2}|6 i+3 j+6 k|=\frac{9}{2}$ square units
A unit vector $\perp$ to the plane $A B C=\frac{\overrightarrow{A B} \times \overrightarrow{A C}}{|\overrightarrow{A B} \times \overrightarrow{A C}|}=\frac{1}{9}(6 i+3 j+6 k)=\frac{1}{3}(2 i+j+2 k)$

# Unit 44 Vectors in Space <281 

## (c) Moment of Force

Let a force $\underline{F}(P \vec{Q})$ act at a point $P$, as shown in the figure. The moment of $\underline{F}$ about $O$
$=$ Product of force $\underline{F}$ and the perpendicular distance $\overrightarrow{O N}$ in the direction of $s$.

$$
\begin{aligned}
& =\overrightarrow{(P Q)}(\overrightarrow{O N})(s)=(P Q)(O P) \sin \theta(s) \\
& =\overrightarrow{O P} \times \overrightarrow{P Q}=\underline{r} \times \underline{F}
\end{aligned}
$$

[Image removed]

Example 22 Find the moment about the point $M(-2,4,-6)$ of the force represented by $\overrightarrow{A B}$, where coordinates of points $A$ and $B$ are $(1,2,-3)$ and $(3,-4,2)$ respectively.
Solution $\overrightarrow{A B}=\overrightarrow{O B}-\overrightarrow{O A}=(3-1) i+(-4-2) j+(2+3) \underline{k}=2 i-6 j+5 \underline{k}$

$$
\overrightarrow{M A}=(1+2) i+(2-4) j+(-3+6) k=3 i-2 j+3 k
$$

Moment of $A B$ about $M(-2,4,-6)=\underline{r} \times \underline{F}=\overrightarrow{M A} \times \overrightarrow{A B}$

$$
\begin{aligned}
& =i \quad j \quad k \\
& =3 \quad-2 \quad 3 \\
& =2 \quad-6 \quad 5 \\
& =(-10+18) i-(15-6) j+(-18+4) k \\
& =8 i-9 j-14 k
\end{aligned}
$$

Magnitude of the moment $=\sqrt{(8)^{2}+(-9)^{2}+(-14)^{2}}=\sqrt{341}$

## EXERCISE 14.3

1. Compute the cross product $a \times b$ and $b \times a$. Check your answer by showing that each $a$ and $b$ are perpendicular to $a \times b$ and $b \times a$.
(i) $\underline{a}=2 i+\underline{j}-\underline{k}, \underline{b}=\underline{i}-\underline{j}+\underline{k}$
(ii) $a=i+3 j+2 k, \underline{b}=2 i-\underline{j}+\underline{k}$
(iii) $\underline{a}=2 i-2 \underline{j}+\underline{k}, \underline{b}=-\underline{i}+\underline{j}+3 \underline{k}$
(iv) $\underline{a}=-4 i+\underline{j}-2 \underline{k}, \underline{b}=2 i+\underline{j}+\underline{k}$
2. Find a unit vector perpendicular to the plane containing $a$ and $b$. Also find sine of the angle between them:
(i) $\underline{a}=i+6 \underline{j}-3 \underline{k}, \underline{b}=2 i+\underline{j}+3 \underline{k}$
(ii) $\underline{a}=-\underline{i}-\underline{j}-\underline{k}, \underline{b}=2 i-3 \underline{j}+4 \underline{k}$
(iii) $\underline{a}=\underline{i}+\underline{j}+\underline{k}, \underline{b}=\underline{i}-\underline{j}-\underline{k}$
(iv) $\underline{a}=5 i+\underline{j}-3 \underline{k}, \underline{b}=-2 i+4 \underline{j}+\underline{k}$

3. Find the area of the triangle, formed by the points $P, Q$ and $R$.
(i) $P(2,3,5) ; Q(1,2,0) ; R(4,1,2)$
(ii) $P(0,0,1) ; Q(2,-1,2) ; R(-1,3,2)$
4. Find the area of a parallelogram, whose vertices are:
(i) $A(1,1,1) ; B(4,2,3) ; C(5,6,7) ; D(2,5,5)$
(ii) $A(4,5,6) ; B(1,3,2) ; C(-2,0,1) ; D(1,2,5)$
5. If the cross product of the vectors $\underline{u}=7 \underline{i}-4 \underline{j}+5 \underline{k}$ and $\underline{v}=a \underline{i}-b \underline{j}+3 \underline{k}$ is zero, then find the values of $a$ and $b$.
6. Which vectors, if any, are perpendicular or parallel
(i) $\underline{u}=5 \underline{i}-\underline{j}+\underline{k} ; \underline{v}=\underline{j}-5 \underline{k} ; \underline{w}=-15 \underline{i}+3 \underline{j}-3 \underline{k}$
(ii) $\underline{u}=\underline{i}+2 \underline{j}-\underline{k} ; \underline{v}=-\underline{i}+\underline{j}+\underline{k} ; \underline{w}=-\frac{\pi}{2} \underline{i}-\pi \underline{j}+\frac{\pi}{2} \underline{k}$
7. Use the definition of cross product, for any vectors $\underline{u}, \underline{v}, \underline{w}$ and scalar $\underline{k}$, prove that
(i) $\underline{u} \times(-u)=0$
(ii) $\underline{u} \times \underline{v}=-v \times \underline{u}$
(iii) $\underline{u} \times(\underline{k} \underline{v})=(\underline{k} \underline{u}) \times \underline{v}=\underline{k}(\underline{u} \times \underline{v})$
(iv) $\underline{u} \times(\underline{v}+\underline{w})=(\underline{u} \times \underline{v})+(\underline{u} \times \underline{w})$
8. Prove that: $\underline{a} \times(\underline{b}+\underline{c})+\underline{b} \times(\underline{c}+\underline{a})+\underline{c} \times(\underline{a}+\underline{b})=0$.
9. If $\underline{a}+\underline{b}+\underline{c}=\underline{0}$, then prove that $\underline{a} \times \underline{b}=\underline{b} \times \underline{c}=\underline{c} \times \underline{a}$
10. Prove that: $\sin (\alpha-\beta)=\sin \alpha \cos \beta+\cos \alpha \sin \beta$
11. Show that $|\underline{a} \times \underline{b}|^{2}=|\underline{a}|^{2}|\underline{b}|^{2}-(\underline{a} \cdot \underline{b})^{2}$
12. Use the definition of cross product, prove that for any vectors $\underline{u}$ and $\underline{v}$ $(\underline{u}+\underline{v}) \times(\underline{u}-\underline{v})=-2(\underline{u} \times \underline{v})$.
13. Find the moment about the point $M(1,-3,3)$ of the force represented by $\overrightarrow{A B}$, where the coordinates of points $A(4,3,-1)$ and $B(-1,3,7)$ are given.
14. A force $\vec{F}=6 \underline{i}+4 \underline{j}-4 \underline{k}$ is applied at the point $A(1,-1,2)$. Find the moment of the force about the point $B(3,-2,3)$.
15. Give a force $\underline{F}=2 \underline{i}+\underline{j}-3 \underline{k}$ acting at a point $A(1,-2,1)$. Find the moment of $\vec{F}$ about the point $B(2,0,-2)$.
16. A force $\underline{F}=-2 \underline{i}+\underline{j}-3 \underline{k}$ is applied at $P(-1,-3,2)$. Find its moment about the point $Q(4,2,2)$.

# 14.4 Scalar Triple Product 

The scalar triple product is a key concept in vector calculus with wide-ranging applications covering various fields. In three-dimensional space, it provides a significant role in calculating the volume of geometric shapes such as parallelepipeds and tetrahedrons, defined by three vectors, which we will learn later in this chapter. Additionally, it plays as a vital tool for determining the coplanarity of vectors, providing a condition to verify whether three vectors lie within the same plane.
There are two types of triple product of vectors:
(a) Scalar Triple Product: $\underline{u} \cdot(\underline{v} \times \underline{w})$
(b) Vector Triple Product: $\underline{u} \times(\underline{v} \times \underline{w})$

In this section we shall study the scalar triple product only.
Let $\underline{u}, \underline{v}$ and $\underline{w}$ be three non-zero vectors
The scalar triple product of vector $\underline{u}, \underline{v}$ and $\underline{w}$ is defined by

$$
\underline{u} \cdot(\underline{v} \times \underline{w}) \quad \text { or } \quad \underline{v} \cdot(\underline{w} \times \underline{u}) \text { or } \quad \underline{w} \cdot(\underline{u} \times \underline{v})
$$

The scalar triple product $\underline{u} \cdot(\underline{v} \times \underline{w})$ is written as

$$
\underline{u} \cdot(\underline{v} \times \underline{w}) \in[\underline{u} \times \underline{w}]
$$

### 14.4.1 The Volume of the Parallelepiped

The triple scalar product $(\underline{u} \times \underline{v}) \cdot \underline{w}$ represents the volume of the parallelepiped having $\underline{u}, \underline{v}$ and $\underline{w}$ as its conterminous edges.
As it is seen from the formula that:

Hence, (i) $\backslash[\underline{u} \times \underline{v}]:=\operatorname{area}$ of the parallelogram with two adjacent sides $\underline{u}$ and $\underline{v}$.
[Image removed]
(ii) $|\underline{w}| \cos \theta=$ height of the parallelepiped
$(\underline{u} \times \underline{v}) \cdot \underline{w}=|\underline{u} \times \underline{v}||\underline{w}| \cos \theta=$ (Area of Parallelogram) (height)
$=$ Volume of the parallelepiped
Similarly, be taking the base plane formed by $\underline{v}$ and $\underline{w}$, we have
The volume of the parallelepiped $=(\underline{v} \times \underline{w}) \cdot \underline{u}$
And by taking the base plane formed by $\underline{w}$ and $\underline{u}$, we have
The volume of the parallelepiped $=(\underline{w} \times \underline{u}) \cdot \underline{v}$
So, we have: $(\underline{u} \times \underline{v}) \cdot \underline{w}=(\underline{v} \times \underline{w}) \cdot \underline{u}=(\underline{w} \times \underline{u}) \cdot \underline{v}$

# 14.4.2 The Volume of the Tetrahedron 

Volume of the tetrahedron $A B C D=\frac{1}{3}$ (area of $A A B C$ )(height of $D$ above the place $A B C$ )

$$
=\frac{1}{3} \times \frac{1}{2} \underline{u} \times \underline{v}(h)
$$

$=\frac{1}{6}$ (Area of parallelogram with $A B$ and $A C$ as adjacent sides) ( $h$ )
$=\frac{1}{3}$ (Volume of the parallelepiped with $\underline{u}, \underline{v}, \underline{w}$ as edges)
[Image removed]

## Nota

As volume is always positive so ignore negative sign if $(u \times v) \cdot w$ is negative.

Thus, volume of tetrahedron $=\frac{1}{6}(\underline{u} \times \underline{v}) \cdot \underline{w}=\frac{1}{6}[\underline{u} \underline{v} \underline{w}]$

### 14.4.3 Scalar Triple Product of Vectors in Terms of Components

Let $\underline{u}=a_{1} \underline{i}+b_{1} \underline{j}+c_{1} \underline{k}, \underline{v}=a_{2} \underline{i}+b_{2} \underline{j}+c_{2} \underline{k}$ and $\underline{w}=a_{3} \underline{i}+b_{3} \underline{j}+c_{3} \underline{k}$

Now,

$$
\underline{v} \times \underline{w}=\left|\begin{array}{lll}
\underline{i} & \underline{j} & \underline{k} \\
a_{2} & b_{2} & c_{2} \\
a_{3} & b_{3} & c_{3}
\end{array}\right|
$$

$$
\begin{aligned}
& \Rightarrow \quad \underline{u} \times \underline{w}=\left(b_{2} c_{3}-b_{3} c_{2}\right) \underline{i}-\left(a_{2} c_{3}-a_{3} c_{2}\right) \underline{j}+\left(a_{2} b_{3}-a_{3} b_{2}\right) \underline{k} \\
& \therefore \quad \underline{u} \cdot(\underline{v} \times \underline{w})=a_{1}\left(\underline{b}_{2} c_{2}-\bar{b}_{3} c_{2}\right)-b_{1}\left(a_{2} c_{3}-a_{3} c_{2}\right)+c_{1}\left(a_{2} b_{3}-a_{3} b_{2}\right) \\
& \Rightarrow \quad \underline{u} \cdot(\underline{v} \times \underline{w})=\left|\begin{array}{lll}
a_{1} & b_{1} & c_{1} \\
a_{2} & b_{2} & c_{2} \\
a_{3} & b_{3} & c_{3}
\end{array}\right|
\end{aligned}
$$

Which is called the determinant formula for scalar triple product of $\underline{u}, \underline{v}$ and $\underline{w}$ in component form.
Example 23 Prove that dot and cross product are interchangeable in scalar triple product.
Solution Consider $\underline{u}=a_{1} \underline{i}+b_{1} \underline{j}+c_{1} \underline{k}, \underline{v}=a_{2} \underline{i}+b_{2} \underline{j}+c_{2} \underline{k}$ and $\underline{w}=a_{3} \underline{i}+b_{3} \underline{j}+c_{3} \underline{k}$ are the arbitrary vectors.
The determinant formula for scalar triple product of vectors $\underline{u}, \underline{v}$ and $\underline{w}$ is given by:
$\underline{u} \cdot(\underline{v} \times \underline{w})=\left|\begin{array}{lll}a_{1} & b_{1} & c_{1} \\ a_{2} & b_{2} & c_{2} \\ a_{3} & b_{3} & c_{3}\end{array}\right|$

$$
\begin{aligned}
& =-\left|\begin{array}{lll}
a_{2} & b_{2} & c_{2} \\
a_{1} & b_{1} & c_{1} \\
a_{3} & b_{3} & c_{3}
\end{array}\right| \quad \text { Interchanging } R_{1} \text { and } R_{2} \\
& =\left|\begin{array}{lll}
a_{3} & b_{3} & c_{3} \\
a_{1} & b_{1} & c_{1} \\
a_{2} & b_{2} & c_{2}
\end{array}\right| \quad \text { Interchanging } R_{1} \text { and } R_{2} \\
& =\underline{w} \cdot(\underline{u} \times \underline{v})=(\underline{u} \times \underline{v}) \cdot \underline{w} \quad(\because \underline{a} \cdot \underline{b}=\underline{b} \cdot \underline{a})
\end{aligned}
$$

Hence, $\underline{u} \cdot(\underline{v} \times \underline{w})=(\underline{u} \times \underline{v}) \cdot \underline{w}$
Thus, the position of dot and cross can be interchanged in scalar triple product.
Example 24 Assuming $i, j$ and $k$ are unit vectors in a cartesian coordinate system.
Prove that $i \cdot j \times k=j \cdot k \times i=k \cdot i \times j$
Sotation Given $i, j$ and $k$ are unit vector,
So, we can write $i=i+0 j+0 k, j=0 i+j+0 k, k=0 i+0 j+k$ then determinant form for scalar triple product of unit vectors $i, j$ and $k$ can be written as:

$$
\begin{aligned}
& i \cdot j \times k=\left|\begin{array}{lll}
1 & 0 & 0 \\
0 & 1 & 0 \\
0 & 0 & 1
\end{array}\right|=1(1-0)-0(0-1)+0(0-0)=1 \\
& j \cdot k \times i=\left|\begin{array}{lll}
0 & 1 & 0 \\
0 & 0 & 1 \\
1 & 0 & 0
\end{array}\right|=0(0-0)-1(0-1)+0(0-0)=1 \text { and } k \cdot i \times j=\left|\begin{array}{lll}
0 & 0 & 1 \\
1 & 0 & 0 \\
0 & 1 & 0
\end{array}\right|=1 \\
& \text { Therefore } i \cdot j \times k=j \cdot k \times i=k \cdot i \times j
\end{aligned}
$$

Example 25 Find the volume of the parallelepiped determined by

$$
\underline{u}=\underline{i}+2 \underline{j}-\underline{k}, \underline{v}=\underline{i}-2 \underline{j}+3 \underline{k}, \underline{w}=\underline{i}-7 \underline{j}-4 \underline{k}
$$

Sotation Volume of the parallelepiped $=\underline{u} \cdot \underline{v} \times \underline{w}=\left|\begin{array}{rrr}1 & 2 & -1 \\ 1 & -2 & 3 \\ 1 & -7 & -4\end{array}\right|$

$$
\begin{aligned}
\Rightarrow \quad \text { Volume } & =1(8+21)-2(-4-3)-1(-7+2)=29+14+5 \\
& =48 \text { cubic units }
\end{aligned}
$$

Example 26 Find the volume of the tetrahedron whose vertices are $A(2,1,8)$, $B(3,2,9), C(2,1,4)$ and $D(3,3,0)$.
Solution $\overrightarrow{A B}=\overrightarrow{O B}-\overrightarrow{O A}=(3-2) \underline{i}+(2-1) \underline{j}+(9-8) \underline{k}=\underline{i}+\underline{j}+\underline{k}$

$$
\begin{aligned}
& \overrightarrow{A C}=\overrightarrow{O C}-\overrightarrow{O A}=(2-2) \underline{i}+(1-1) \underline{j}+(4-8) \underline{k}=0 \underline{i}-0 \underline{j}-4 \underline{k} \\
& \overrightarrow{A D}=\overrightarrow{O D}-\overrightarrow{O A}=(+3-2) \underline{i}+(3-1) \underline{j}+(0-8) \underline{k}=\underline{i}+2 \underline{j}-8 \underline{k}
\end{aligned}
$$

Volume of the tetrahedron $=\frac{1}{6}[\overrightarrow{A B} \overrightarrow{A C} \overrightarrow{A D}]$

$$
\begin{aligned}
& =\frac{1}{6}\left|\begin{array}{lll}
1 & 1 & 1 \\
0 & 0 & -4 \\
1 & 2 & -8
\end{array}\right|=\frac{1}{6}[1(0+8)-1(0+4)+1(0-0)] \\
& =\frac{1}{6}[8-4]=\frac{4}{6}=\frac{2}{3} \text { cubic units }
\end{aligned}
$$

# 14.4.4 Coplanar Vectors and Condition for Coplanarity of Three Vectors 

Vectors are coplanar if they lie in the same plane or can be combined in the same plane.
Consider the three coplanar vectors $u, v$ and $w$ in a plane as shown in a figure.
The cross product $v \times w$ gives a vector that is perpendicular to both the vectors yand $w$, As $u, v$ and $w$ are coplanar, so
[Image removed]
$y \times w$ is also perpendicular to $u$
Thus, the dot product of $u$ and $v \times w$ is zero. i.e.,

$$
u \cdot(v \times w)=0 \quad \because \text { If vectors } a \text { and } b \text { are perpndicular then } a \cdot b=0
$$

Thus, we conclude that if the three vectors $u, v$ and $w$ are coplanar then their scalar triple product is zero.

## Properties of Scalar Triple Product

1. If $u, v$ and $w$ are coplanar, then the volume of the parallelepiped so formed is zero that is $(u \times v) \cdot w=0$ and hence the vectors $u, v, w$ are coplanar $\Leftrightarrow(u \times v) \cdot w=0$
2. If any two vectors of scalar triple product are equal, then its value is zero i.e., $[u u w]=[u v v]=[u w w]=0$
Example 27 Prove that four points
$A(-3,5,-4), B(-1,1,1), C(-1,2,2)$ and $D(-3,4,-5)$ are coplanar.
Proof: $\quad \overrightarrow{A B}=\overrightarrow{O B}-\overrightarrow{O A}=(-1+3) \underline{i}+(1-5) \underline{j}+(1+4) \underline{k}=2 \underline{i}-4 \underline{j}+5 \underline{k}$

$$
\begin{aligned}
& \overrightarrow{A C}=\overrightarrow{O C}-\overrightarrow{O A}=(-1+3) \underline{i}+(2-5) \underline{j}+(2+4) \underline{k}=2 \underline{i}-3 \underline{j}+6 \underline{k} \\
& \overrightarrow{A D}=\overrightarrow{O D}-\overrightarrow{O A}=(-3+3) i+(4-5) j+(-5+4) k=0 i-j-k=-j-k
\end{aligned}
$$

Volume of the parallelepiped formed $\overrightarrow{A B}, \overrightarrow{A C}$ and $\overrightarrow{A D}$ is

$$
\begin{aligned}
& \overrightarrow{[A B A C A D]}=\left|\begin{array}{rrr}
2 & -4 & 5 \\
2 & -3 & 6 \\
0 & -1 & -1
\end{array}\right|=2(3+6)+4(-2-0)+5(-2-0) \\
& =18-8-10 \\
& =0
\end{aligned}
$$

As the volume is zero, so the points $A, B, C$ and $D$ are coplaner.
Example 28 Find the value of $\alpha$, so that $\alpha i+j, i+j+3 k$ and $2 i+j-2 k$ are coplanar.
Solution Let $\underline{u}=\alpha i+j+0 k, \underline{v}=i+j+3 k$ and $\underline{w}=2 i+j-2 k$ be three given vectors. Scalar triple product of given vectors is

$$
\begin{aligned}
& {[\underline{u} \underline{v} \underline{w}]=\left|\begin{array}{lll}
\alpha & 1 & 0 \\
1 & 1 & 3 \\
2 & 1 & -2
\end{array}\right|} \\
& =\alpha(-2-3)-1(-2-6)+0(1-2) \\
& =-5 \alpha+8
\end{aligned}
$$

The vectors will be coplanar if $-5 \alpha+8-0 \Rightarrow \alpha=\frac{8}{5}$

# 14.4.5 Applications of Vectors in Real World 

Example 29 A plumber exerts a force of 30 pounds along the negative $y$-axis on a lever connected to a machine. The pivot point of the lever is at the origin $(0,0,0)$, and the force is applied at the point ( $1.2 \mathrm{ft}, 0.5 \mathrm{ft}, 0 \mathrm{ft}$ ). Determine the torque produced by this force about the pivot point.
Solution The position vector $r$ from the origin to the point $(1.2,0.5,0)$ is given by $r=1.2 i+0.5 j+0 k$

The force $\vec{F}$ is exerted downward along negative $y$-axis with a magnitude of 30 pounds is

$$
\underline{F}=0 i-30 j+0 k
$$

[Image removed]

Torque $\tau$ produced by the force $=r \times \underline{F}$
Using determinant formula of cross product

$$
\begin{aligned}
\underline{\tau} & =\left|\begin{array}{ccc}
i & j & k \\
1.2 & 0.5 & 0 \\
0 & -30 & 0
\end{array}\right| \\
& =0 i-0 j-36 k \\
\underline{\tau} & =-36 k \text { pound-feet }
\end{aligned}
$$

Thus, the torque is 36 feet-pounds in the negative $z$-direction
Example 30 During a building construction, a crane exerts a force to pull a concrete block, represented by the vector $\underline{F}=[4500,3300,2140]$ Newton. Each component corresponds to the force exerted along the $x, y$, and $z$ axes, respectively. What is the magnitude of this force?
Solution Using the formula for the magnitude of a vector in three-dimensional space

$$
\begin{aligned}
|\underline{F}| & =\sqrt{x^{2}+y^{2}+z^{2}} \\
& =\sqrt{4500^{2}+3300^{2}+2140^{2}} \\
& =\sqrt{20250000+10890000+4579600} \\
& =\sqrt{35719600} \\
& =5976.59
\end{aligned}
$$

The magnitude of the force exerted by the crane is approximately 5976.59 Newton.
Example 11 The components of $\underline{u}=300 \underline{i}+250 \underline{j}+180 \underline{k}$ represent the respective number of jackets, shoes, and handbags sold at a store. The components of $\underline{y}=3500 \underline{i}+4200 \underline{j}+6840 \underline{k}$ represent the respective prices (in rupees) per unit for each product. Find $\underline{u} \cdot \underline{v}$ and explain what the result tells us in real life.
Solution The dot product of $\underline{u}$ and $\underline{v}=\underline{u} \cdot \underline{v}$

$$
\begin{aligned}
& =(300 \underline{i}+250 \underline{j}+180 \underline{k}) \cdot(3500 \underline{i}+4200 \underline{j}+6840 \underline{k}) \\
& =1,050,000+1,050,000+1,231,200 \\
& =3,331,200
\end{aligned}
$$

The result $\underline{u} \cdot \underline{v}=3,331,200$ tells us that total revenue generated from selling all the three product is Rs. 3,331,200.

# EXERCISE 14.4 

1. Find the volume of parallelepiped for which the given vectors are three edges
(i) $\underline{u}=3 i+2 k ; \quad \underline{v}=i+2 j+k ; \quad \underline{w}=-j+4 k$
(ii) $\underline{u}=i-4 j-k ; \quad \underline{v}=i-j-2 k ; \quad \underline{w}=2 i-3 j+k$
(iii) $\underline{u}=i-2 j+3 k ; \quad \underline{v}=2 i-j-k ; \quad \underline{w}=j+k$
2. Verify that $a \cdot b \times c=b \cdot c \times a=c \cdot a \times b$

If $a=3 i-j+5 k ; \quad b=4 i+3 j-2 k$ and $c=2 i+5 j+k$
3. Prove that the vectors $i-2 j+3 k,-2 i+3 j-4 k$ and $i-3 j+5 k$ are coplanar.
4. Find the constant $a$ such that the vectors are coplanar.
(i) $i-j+k, i-2 j-3 k$ and $3 i-\alpha j+5 k$
(ii) $i-2 \alpha j-k, \quad i-2 j+2 k$ and $\alpha i-2 j+k$
5. Prove that the points whose position vectors are $A(-6 i+3 j+2 k)$, $B(3 i-2 j+4 k), C(5 i+7 j+3 k), D(-13 i+17 j-k)$ are coplanar.
6. (a) Find the value of :
(i) $2 i \times 2 j \cdot k$
(ii) $3 j \cdot k \times i$
(iii) $[k i j]$
(iv) $[i i k]$
(b) Prove that $u \cdot(v \times w)+v \cdot(w \times u)+w \cdot(u \times v)=3 u \cdot(v \times w)$
7. Find volume of tetrahedron with the vertices
(i) $(0,1,2),(3,2,1),(1,2,1)$ and $(5,5,6)$
(ii) $(2,1,8),(3,2,9),(2,1,4)$ and $(3,3,10)$
8. Prove that the points whose position vectors are $A(3 i+2 j-k), B(i-2 j+k)$, $C(6 i+4 j-2 k), D(9 i+6 j-3 k)$ are coplanar.
9. Prove that for any three non-zero vector $\underline{u}, \underline{v}$ and $\underline{w}$ $(u+v) \cdot[(v+w) \times(w+u)]=2[u v w]$
10. Consider a parallelepiped determined by the vector $\underline{u}=2 i+4 j-3 k$, $\underline{v}=5 i-3 j+6 k$ and $w=4 i-7 j-2 k$. If the base of the parallelepiped is define by the vectors $\underline{u}$ and $\underline{v}$ then find the height of the parallelepiped.
11. A mechanic applies a force of 50 pounds along the positive $x$-axis on a wrench connected to a bolt. The pivot point of the wrench is at the origin $(0,0,0)$, and the force is applied at the point ( $0 \mathrm{ft}, 2 \mathrm{ft}, 3 \mathrm{ft}$ ). Determine the torque produced by this force about the pivot point.

12. A drone flies from point $(1,2,5)$ to point $(4,6,9)$, with each unit representing a meter. What is the magnitude of the displacement the drone experienced during this flight?
13. The vector $u=50 i+75 j+65 k$ shows how many belts, pants, and shirts were sold at a store. The vector $w=1500 i+3500 j+3000 k$ shows the price (in rupees) of each item. Find $u \cdot w$ and explain what the result tells us in real life.
14. A force $F=(20,-10,30) \mathrm{N}$ is applied at a point $P(2,-1,4)$ in 3D space. The pivot point is at $M(1,2,-3)$. Calculate the torque produced by this force about the pivot point $M$.
15. An electric shop sells three types of appliances: Fans, Heaters, and Ovens. The monthly sales quantities are 500 units of Fans, 300 units of Heaters and 200 units of Ovens. The profit per unit for each appliance is Rs 500 for Fans, Rs 400 for Heaters, and Rs 2,000 for Ovens.
(a) Represent the monthly sales quantities and the profit per unit as vectors.
(b) Calculate the total monthly profit using vector operations.

# Answers 

## EXERCISE 1.1

1. (i) $\left(\frac{-4}{65}, \frac{-7}{65}\right)$
(ii) $\left(\frac{\sqrt{2}}{7}, \frac{\sqrt{5}}{7}\right)$
(iii) $(1,0)$
2. (i) $\frac{-27}{41}-\frac{38}{41} i$
(ii) $\frac{-17}{2}-\frac{7}{2} i$
(iii) $\frac{1}{2}+\frac{i}{2}$
(iv) $\frac{-44}{25}+\frac{117}{25} i$
3. $\frac{11}{13}-\frac{23}{13} i$
4. (i) $2 \sqrt{145}$
(ii) $\sqrt{149}$
(iii) $\sqrt{1354}$
(iv) $109 \sqrt{109}$
5. 2

## EXERCISE 1.2

1. (i) $x=-19, y=22$
(ii) $x=9, y=6$
(iii) $x=-11, y=28$
2. $x=14, y=9$
3. (i) $x=3 \sqrt{5}, y=2 \sqrt{5} \propto x=-3 \sqrt{5}, y=-2 \sqrt{5}$
(ii) $x=6 \sqrt{2}, y=2 \sqrt{2} \propto x=-6 \sqrt{2}, y=-2 \sqrt{2}$
(iii) $x=0.46, y=0.95 \quad$ or $\quad x=-0.46, y=-0.95$
4. $\alpha=-\frac{4}{3}$
5. $x=8, y=3, a=2, b=1$
6. (i) $3-4 i \mathrm{or}-3+4 i$
(ii) $3-i \mathrm{or}-3+i$
(iii) $2 \sqrt{5}=3 \sqrt{5} i \mathrm{or}-2 \sqrt{3}+3 \sqrt{3} i$
(iv) $12+5 i \mathrm{or}-12-5 i$
7. $\pm(5-2 \sqrt{5} i)$
8. $x=\frac{1}{25}, y=\frac{-57}{25}$
9. $x=\frac{-24}{29}, y=\frac{31}{29}$
10. $u=-8, v=13$
11. $\alpha=\frac{5}{2}$

## EXERCISE 1.3

1. (i) $(a+i 2 b)(a-i 2 b)$
(ii) $(3 a+i 4 b)(3 a-i 4 b)$
(iii) $3(x+i y)(x-i y)$
(iv) $9(4 x+i 5 y)(4 x-i 5 y)$
(v) $(z-i)(z-i)$
(vi) $(z+3-2 i)(z+3+2 i)$
(vii) $(z+2-i)(z+2+i)$
(viii) $2\left(z-\frac{11-3 i}{2} i z-\frac{11+3 i}{2}\right)$
2. (i) $(z+2)(z-1+i \sqrt{3})(z-1-i \sqrt{3})$
(ii) $(z+3)\left(z-\frac{3}{2}+\frac{3 \sqrt{3} i}{2}\right)\left(z-\frac{3}{2}-\frac{3 \sqrt{3} i}{2}\right)$
(iii) $(z-2)(z-4 i)(z+4 i)$
(iv) $(z-2)(z+2)(z-5 i)(z+5 i)$
(v) $(z-2)(z+2)(z-2 i)(z+2 i)$
(vi) $(z+1)(z-1)(z+2 i)(z-2 i)$
(vii) $(z-\sqrt{2} i)(z+\sqrt{2} i)(z-\sqrt{3} i)(z+\sqrt{3} i)$
(viii) $(z-9)(z+9)(z-7 i)(z+7 i)$
3. Roots: $3,-3,4 i,-4 i$ Linear factor: $(z+3)(z-3)(z+4 i)(z-4 i)$ 4. (i) $z=\frac{3 \pm i \sqrt{23}}{4}$
(ii) $z=3 \pm i \sqrt{21}$
(iii) $z=3 \pm \frac{\sqrt{69} i}{3}$
(iv) $z=-2 \pm 3 i$
(v) $z=-\frac{3}{2}+\frac{3}{2} i$
(vi) $z=\frac{5 \pm \sqrt{59} i}{6}$
4. (i) $2,-2,2 i,-2 i$
(ii) $0,3,-3,3 i,-3 i$
(iii) $0,1,-1, i,-i$
(iv) $5, i,-i$
(v) $\sqrt{7},-\sqrt{7}, \frac{\sqrt{3} i}{2},-\frac{\sqrt{3} i}{2}$
(vi) $-1, i,-i$

6. $$x = -2z^3 + 6z^2 - 8z + 24$$  
7. $$x = 10z^4 + 30z^2 - 40$$  
8. $$x = -3z^4 + 6z^3 + 42z^2 - 96z + 96$$

## EXERCISE 1.4

1. i) $$(2, 2m, 2m^3)$$  
   ii) $$(-2, -2m, -2m^3)$$  
   iii) $$(-3, -3m, -3m^3)$$  
   iv) $$(4, 4m, 4m^3)$$  
   v) $$(-5, -5m, -5m^3)$$  
2. (i) $$2, -2, 2i, -2i$$  
   (ii) $$3, -3, 3i, -3i$$

(iii) $$5, -5, 5i, -5i$$

4. (i) $$-1$$  
   (ii) $$-32$$

7. 0

## EXERCISE 1.5

1. (i)

[Image removed]

[Image removed]
2. i) $5(\cos 36.87+i \sin 36.87)$
ii) $\sqrt{2}\left(\cos \frac{\pi}{4}+i \sin \frac{\pi}{4}\right)$
iii) $1 \cdot\left(\cos \frac{\pi}{3}+i \sin \frac{\pi}{3}\right)$
iv) $5\left(\cos \frac{4 \pi}{3}+i \sin \frac{4 \pi}{3}\right)$
(v) $1 \cdot\left(\cos \left(-\frac{\pi}{2}\right)+i \sin \left(\frac{\pi}{2}\right)\right)$
(vi) $1 \cdot\left(\cos \left(-\frac{\pi}{6}\right)+i \sin \left(-\frac{\pi}{6}\right)\right)$
(vii) $1 \cdot\left(\cos \left(\tan ^{-1} \frac{7}{24}\right)+i \sin \left(\tan ^{-1} \frac{7}{24}\right)\right)$
3.
(i) $2-2 \sqrt{3} i$
(ii) $-\frac{3 \sqrt{3}}{4}-\frac{3}{4} i$
(iii) $6.76-1.81 i$
(iv) $-10.62-2.85 i$
(v) $-0.86+3.21 i$
(vi) $1.68-1.09 i$
4. (i) $-3.86-2.03 i$
(ii) $-8.86-10.69 i$
(iii) $45\left(\cos \frac{19 \pi}{12}+i \sin \frac{19 \pi}{12}\right)$
(iv) $\frac{9}{5}\left(\cos \frac{11 \pi}{12}+i \sin \frac{11 \pi}{12}\right)$
5. (i) $-3.86+1.03 i$
(ii) $17.38-4.65 i$
(iii) $-66.68+38.5 i$
(iv) $-\frac{7}{11}+0 i$
7. $2\left(\cos 120+i \sin 120^{\circ}\right),-1+i \sqrt{3}$
8. $10(\cos 150+i \sin 150),-5 \sqrt{3}+5 i$
9. $|z|=2 \sqrt{2}, \arg (z)=\frac{5 \pi}{4}+2 \pi \pi$
10. $y=\sqrt{3} x-2 \sqrt{3}+1$
13. $y=-x$
14. $y=-\frac{7}{3} x-\frac{2}{15}$
15. $y=-x+\frac{1}{3}$
17. 1
18. $120\left(\cos \frac{\pi}{12}-i \sin \frac{\pi}{12}\right)$
19. Rectangular form: $2+14 i$, Polar From: $10 \sqrt{2}(\cos 81.87+i \sin 81.87)$

# EXERCISE 2.1 

1. (a) (i) 8
(ii) -1
(iii) $x^{2}-4 x+3$
(iv) $x^{4}+6 x^{2}+8$
(b) (i) $\sqrt{-3}$
(ii) $\sqrt{3}$
(iii) $\sqrt{2 x-1}$
(iv) $\sqrt{2 x^{2}+9}$

2. (i) 4 (ii) $\frac{2}{h} \cos \left(a+\frac{h}{2}\right) \sin \left(\frac{h}{2}\right)$ (iii) $h^{2}+3 a h+h+3 a^{2}+2 a$
(iv) $\frac{\sinh }{h \cos a \cos (a+h)}$
3. (a) $A=\frac{P^{2}}{16}$
(b) $C=2 \sqrt{\pi A}$
(c) $S=6 V^{2 / 3}$
4. (i) Domain $g=(-\infty, \infty)$, Range $g=(-\infty, \infty)$
(ii) Domain $g=[-2, \infty)$, Range $g=[0, \infty)$
(iii) Domain $g=(-\infty, \infty)$, Range $g=(-\infty, 10)$
(iv) Domain $g=(-\infty, \infty)$, Range $g=[0, \infty)$
(v) Domain $g=R-\{3\}$, Range $g=R-\{-1\}$
5. $a=2, b=-2$
6. (i) (a) 30 m
(b) 17.5 m
(c) 11.1 m
(ii) $x=2 \sec$
7. (i) Domain $f=(-\infty, \infty)$, Range $f=(-\infty, \infty)$
(ii) Yes, the function is one-to-one, because equal outputs implies equal inputs.
(iii) Yes, the function is onto when the codomain is all real numbers.
8. (i) Domain $f=R-\{-1\}$, Range $f=R-\{2\}$
(ii) $f(x)$ is not onto.
9. $g(x)$ is surjective.

# EXERCISE 2.2 

1. (i)
[Image removed]
(ii)
[Image removed]
(iii)
[Image removed]

[Image removed]
(iv)
[Image removed]
(ii)
[Image removed]
(iii)
[Image removed]
(iv)
[Image removed]

[Image removed]

[^0]
[^0]:    (v)
    (vi)
    (vii)

[Image removed]
(vi)
[Image removed]
4. (i) 14 months
(ii) 373.2 metres
5. 25 grams

# EXERCISE 3.1 

1. (i) Minimum value at $x=-3$ is 4
(ii) Minimum value at $x=-2$ is -4
(iii) Maximum value at $x=4$ is 29
(iv) Maximum value at $x=\frac{-3}{2}$ is $\frac{-11}{4}$
(v) Minimum value at $x=-1$ is -16 (vi) Maximum value at $x=\frac{1}{4}$ is $\frac{169}{8}$
2. (i) Minimum value at $x=2$ is -4 ; Domain $f=(-\infty, \infty)$; Range $f=[-4, \infty)$
(ii) Minimum value at $x=\frac{5}{2}$ is $\frac{-1}{4}$; Domain $f=(-\infty, \infty)$; Range $f=\left[\frac{-1}{4}, \infty\right)$
(iii) Maximum value at $x=1$ is -7 ; Domain $f=(-\infty, \infty)$; Range $f=(-\infty,-7]$
(iv) Minimum value at $x=2$ is 0 ; Domain $f=(-\infty, \infty)$; Range $f=[0, \infty)$
(v) Minimum value at $x=-1$ is -9.3 ; Domain $f=(-\infty, \infty)$; Range $f=[-9.3, \infty)$
(vi) Maximum value at $x=\frac{-1}{2}$ is $\frac{25}{4}$; Domain $f=(-\infty, \infty)$; Range $f=\left(-\infty, \frac{25}{4}\right]$
3. (i) $f^{-1}(x)=\sqrt{x+3}$; Domain $f^{-1}=[-3, \infty)$; Range $f^{-1}=(-\infty, 0]$

(ii) $f^{-1}(x)=-3-\sqrt{5+x}$; Domain $f^{-1}=(-5, \infty)$; Range $f^{-1}=(-3, \infty)$
(iii) $f^{-1}(x)=\frac{4+\sqrt{2-3+x}}{2}$; Domain $f^{-1}=[-3, \infty)$; Range $f^{-1}=[2, \infty)$
(iv) $f^{-1}(x)=\frac{1+\sqrt{3 x-17}}{3}$; Domain $f^{-1}=[71, \infty)$; Range $f^{-1}=[5, \infty)$
(v) $f^{-1}(x)=3+\sqrt{\frac{x-1}{2}}$; Domain $f^{-1}=[1, \infty)$; Range $f^{-1}=[3, \infty)$
(vi) $f^{-1}(x)=-4-\sqrt{\frac{(x+5)}{3}}$; Domain $f^{-1}=(-\infty,-5)$; Range $f^{-1}=(-\infty,-4]$
4.
(i) $\{-2,2\}$
(ii) $\{-1,-4\}$
(iii) $\{3-\sqrt{5}, 3+\sqrt{5}\}$
(iv) $\left\{\frac{3-\sqrt{7}}{2}, \frac{1}{2}, \frac{3}{2}, \frac{3+\sqrt{7}}{2}\right\}$
(v) $\{(-3,3)\}$
(vi) $\left\{\frac{3-\sqrt{17}}{2}\right\} \cup\left\{\frac{3+\sqrt{17}}{2}, \infty\right\}$
(vii) $\{(-\sqrt{5}+3, \sqrt{5}+3)\}$
(viii) $\left\{\frac{3}{2}, \frac{\sqrt{17}+3}{4}\right\} \cup\left\{\frac{\sqrt{17}+3}{4}, 3\right\}$

# EXERCISE 3.2 

1. (i) $\left\{1, \frac{1}{2}\right\}$
(ii) $\{-2,1\}$
(iii) $\left\{\frac{-3}{2}, 1\right\}$
(iv) $\left\{\frac{a+b}{a b}, \frac{2}{a+b}\right\}$
(v) $\}$
(vi) $\left\{\frac{1}{3}, \frac{-16}{3}\right\}$
(vii) $\{4\}$
(viii) $\{4,20\}$
(ix) $\{2\}$
(x) $\{4\}$
2. 20 days
3. 15 sheep
4. 97 dozen eggs
5. 6 hours
$0 \leq \mathrm{s} \leq 4756 \mathrm{~km} / \mathrm{h}$
6. $[0.586 \mathrm{sec}, 3.414 \mathrm{sec}]$

## EXERCISE 4.1

2. (i) $\left[\begin{array}{rrr}-2 & -2 & 3 \\ 2 & 0 & -3 \\ 0 & -2 & 3\end{array}\right]$
(ii) $\left[\begin{array}{rrr}1 & 1 & 1 \\ 2 & -3 & 4 \\ -4 & -2 & 2\end{array}\right]$
(iii) $\left[\begin{array}{rrr}-3 & -2 & 5 \\ 3 & -5 & -3 \\ -3 & -6 & 4\end{array}\right]$
(iv) $\left[\begin{array}{rrr}-1 & -2 & 1 \\ 1 & 5 & -3 \\ 3 & 2 & 2\end{array}\right]$

5. $A+A^{\prime}=\left[\begin{array}{ccc}-2 & 3 & 0 \\ 3 & 0 & 7 \\ 0 & 7 & 6\end{array}\right], A-A^{\prime}=\left[\begin{array}{ccc}0 & 1 & 6 \\ -1 & 0 & -3 \\ -6 & 3 & 0\end{array}\right], A A^{\prime}=\left[\begin{array}{ccc}14 & 5 & 22 \\ 5 & 5 & 3 \\ 22 & 3 & 43\end{array}\right]$,
$A^{\prime} A=\left[\begin{array}{ccc}11 & -17 & -10 \\ -17 & 29 & 21 \\ -10 & 21 & 22\end{array}\right],\left(A^{\prime}\right)^{\prime}=\left[\begin{array}{ccc}-1 & 2 & 3 \\ 1 & 0 & 2 \\ -3 & 5 & 3\end{array}\right]$
6. $\left[\begin{array}{ccc}-1 & -1 & -3 \\ -1 & -3 & -10 \\ -5 & 4 & 2\end{array}\right]$

# EXERCISE 4.2 

1. (i) -21 (ii) $9 a b^{3}$ (iii) $4 x y z$
2. (i) $A_{15}=-10, A_{23}=-2, A_{33}=-5,|A|=-5$ (ii) $B_{31}=-3, B_{32}=5, B_{33}=-1,|B|=-1$
3. (i) $x=\frac{1}{2}$
(ii) $x=-1$ or 2
(iii) $x=2$ or 3
4. (i) 147,0
(ii) 0,96
5. $A=\frac{1}{2}, A=-4$

## EXERCISE 4.3

1. (i) $\left[\begin{array}{ccc}1 & \frac{17}{4} & \frac{1}{2} \\ 0 & \frac{-1}{2} & 0 \\ \frac{1}{3} & \frac{11}{6} & \frac{1}{3}\end{array}\right]$
(ii) $\left[\begin{array}{ccc}-\frac{-2}{5} & -2 & \frac{7}{5} \\ \frac{4}{5} & \frac{3}{10} & -4 \\ \frac{1}{5} & \frac{1}{5} & -1 \\ \frac{1}{5} & \frac{1}{5} & \frac{-1}{5}\end{array}\right]$
(iii) $\left[\begin{array}{ccc}-\frac{-13}{3} & \frac{8}{3} & \frac{26}{3} \\ \frac{2}{3} & \frac{-1}{3} & -4 \\ \frac{2}{3} & \frac{-1}{3} & -1 \\ \frac{2}{3} & \frac{-1}{3} & \frac{-1}{3}\end{array}\right]$
2. (i) Rank $=3$
(ii) Rank $=3$
(iii) Rank $=4$
3. (i) $\{(1,0,1)\}$
(ii) $\left\{\left(\frac{68}{55}, \frac{59}{55}, \frac{62}{55}\right)\right\}$
(iii) $\left\{\left(\frac{8}{3}, 2,-\frac{7}{3}\right)\right\}$
4. (i) $\{(1,1,0)\}$
(ii) $\left\{\left(\frac{-8}{9}, \frac{10}{9}, \frac{11}{9}\right)\right\}$
(iii) $\{(1,1,1)\}$
5. (i) $\left\{\left(\frac{19}{23}, \frac{9}{23}, \frac{12}{23}\right)\right\}$
(ii) $\left\{\left(\frac{22}{9}, \frac{1}{3},-\frac{10}{9}\right)\right\}$
(iii) $\left\{\left(\frac{61}{16}, \frac{-1}{4}, \frac{-13}{16}\right)\right\}$

6. (i) $\{(0,0,0)\}$
(ii) $x_{1}=2 t, x_{2}=-t, x_{3}=t$
(iii) $x_{1}=-3 t, x_{2}=2 t, x_{3}=t$
7. $A^{\prime}(-4,1), B^{\prime}(2,5), C^{\prime}(0,-3)$
8. $A^{\prime}(-6,-4,1)$
9. $\frac{3 x^{\prime}-y^{\prime}}{2}=\left(y^{\prime}-2 x^{\prime}\right)^{2}$
10. $\left[\begin{array}{l}16 \\ 22 \\ 15\end{array}\right]\left[\begin{array}{l}36 \\ 43 \\ 49\end{array}\right]\left[\begin{array}{l}21 \\ 26 \\ 16\end{array}\right]$
11. HOLD FIRE

# EXERCISE 5.1 

1. $\frac{1}{x-1}-\frac{1}{x+1}$
2. $\frac{1}{x-a}-\frac{1}{x-b}$
3. $1+\frac{1}{x-1}-\frac{1}{x+1}$
4. $\frac{1}{2(x+1)}+\frac{1}{x+2}-\frac{3}{2(x+3)}$
5. $\frac{1}{x+1}-\frac{1}{x+2}+\frac{1}{x+3}$
6. $4 x+5+\frac{2}{x-1}-\frac{1}{x+1}$
7. $\frac{1}{x-1}+\frac{1}{x-2}+\frac{1}{x-3}$
8. $1+\frac{3}{x-4}-\frac{24}{x-5}+\frac{30}{x-6}$
9. $\frac{a}{(a-b)(c-a)\left(x^{2}+a\right)}+\frac{b}{(a-b)(b-c)\left(x^{2}+b\right)}+\frac{c}{(c-a)(b-c)\left(x^{2}+c\right)}$
10. $\frac{1}{x-1}+\frac{2}{(x-1)^{2}}$
11. $-\frac{1}{4(x+1)}+\frac{1}{4(x-1)}+\frac{1}{2(x-1)^{2}}$
12. $\frac{3}{x-1}+\frac{10}{(x-1)^{2}}+\frac{2}{(x-1)^{3}}$
13. $\frac{1}{x}-\frac{1}{x+1}-\frac{1}{(x+1)^{2}}-\frac{1}{(x+1)^{3}}$
14. $\frac{2}{x+1}+\frac{2}{x-1}+\frac{1}{(x-1)^{2}}$
15. $\frac{3}{x-2}-\frac{3}{x+2}$

## EXERCISE 5.2

1. $\frac{1}{x+1}+\frac{x+2}{x^{2}+1}$
2. $\frac{1}{3(x-2)}-\frac{x-1}{3\left(x^{2}+3 x+5\right)}$
3. $\frac{1}{x-2}-\frac{x+2}{x^{2}+2}-\frac{2(3 x+5)}{\left(x^{2}+2\right)^{2}}$
4. $\frac{2}{x+1}+\frac{x+1}{x^{2}-x+1}$
5. $1-\frac{2}{x^{2}+1}+\frac{1}{\left(x^{2}+1\right)^{2}}$
6. $\frac{1}{2-x}+\frac{1}{2+x}-\frac{2}{x^{2}+4}-\frac{8}{\left(x^{2}+4\right)^{2}}$

## EXERCISE 6.1

1. (i) $24,28,32,36$ (ii) $-3,-5,-7,-9$
2. (i) $8,11,14$
(ii) $3,5,13$
(iii) $-4,-3,0$
(iv) $-1,3, \frac{3}{5}$

# Answers

## (v) 3, 4, 14

### (vi) 1, 25, 5929

### (vii) 4, 16, 36

### (viii) -7, 28, -63

### (vii) -7, 28, -63

### (viii) 3, 120

### (vii) $a_1 r^{n-1}$

### (viii) $\frac{n a_2}{b_1 + c_2}$

### (viii) $\frac{1}{a_1 + (n-1) d}$

## EXERCISE 6.2

1. (i) $d = 7; 30,37$
   (ii) $d = \sqrt{2}; 5 + 3\sqrt{2}, 5 + 4\sqrt{2}$
   2. (i) 2, 15, 28
   (ii) 12, -1, -14

2. $3n + 7, 4 + 6n$

4. (i) 94
   (ii) -47

5. 75

6. No

7. 5

8. 25

9. 62

10. 7, 12, 17, ... ; 502

12. 128

13. 164

14. $\left(\frac{7n-4}{7}\right)^{10}$; No

15. 13

16. 3 : 4 : 5

## EXERCISE 6.3

1. (i) 2
   (ii) $a^2 + b^2$
2. 1, 21
3. $\frac{25}{6\sqrt{2}}, \frac{19}{3\sqrt{2}}, \frac{17}{2\sqrt{2}}, \frac{32}{3\sqrt{2}}, \frac{77}{6\sqrt{2}}$
4. 5, 9 or 9,5

7. 0

## EXERCISE 6.4

1. (i) 630
   (ii) $\frac{n(n+7)}{2\sqrt{5}}$
2. (i) 1300
   (ii) 230
   (iii) 1932

3. 22

4. 14, 51

5. $9cm, 12cm, 15cm$

6. (i) $n(3n-2)$
   (ii) $\frac{n}{2}(9n-13)$

7. 650

8. 385

9. 200000

10. $3 + 7 + 11+$

11. 73

12. 5, 8, 11 or 11, 8, 5

13. 32

14. 5, 7, 9, 11 or 11, 9, 7, 5

15. 3, 4, 5, 6, 7 or 7, 6, 5, 4, 3

17. 11

## EXERCISE 6.5

1. $\frac{-3}{16}$
2. 6561
3. 5
4. (i) 243, 81, 27, 9, 3
   (ii) $579, \frac{-579}{2}, \frac{579}{4}, \frac{-579}{8}, \frac{579}{16}$
5. -64
6. 2, 6, 18, ...; $2 \cdot 3^{n-1}$
7. $\sqrt{mn}$
8. 2, 6, 18 or 18,6, 2
9. 81 · $\sqrt[4]{9}$
10. 2, 7, 12 or 10, 7, 4
11. 1, 2, 3 or 17, 2, -13
12. $\frac{-81}{4}$

## EXERCISE 6.6

1. (i) $4l$ or $-4l$
   (ii) 4 or -4
   (iii) $3\sqrt{6}$ or $-3\sqrt{6}$
2. 6, 12, 24, 48
3. $\frac{1}{2}$
4. 4, 16 or 16,4
5. 2,8 or 8, 2

## EXERCISE 6.7

1. $\frac{7174453}{4782969}$
2. 4, 172
3. (i) $\frac{2}{9} \left[ n-\frac{1}{9} \left( 1-\frac{1}{10^n} \right) \right]$
   (ii) $\frac{1}{3} \left[ \frac{10}{9} \left( 10^n-1 \right)-n \right]$
4. (i) $\frac{a(1-b)(1-a^*)-b(1-a)(1-b^*)}{(a-b)(1-a)(1-b)}$
   (ii) $\frac{r}{1-k} \left( \frac{1-r^2}{1-r} - \frac{k(1-k^*_{r} )}{1-kr} \right)$
5. $\frac{15(1-t)}{8}$

# EXERCISE 6.8 

1. 14080
2. $2(4 n-1) 3^{n-1}$
3. $(2 n+3)(-3)^{n} ;-195$
4. (i) $6+(4 n-6) 2^{n}$
(ii) $\frac{3}{2}\left[1-(n+1) 3^{n}+n \cdot 3^{n+1}\right]$
(iii) $4-\frac{4 / 1}{3 \backslash 4} \cdot \frac{4}{3}(3 n-1) \cdot \frac{1}{4}$
(iv) $\frac{15}{8}-\frac{5}{4}(2 n-1) \cdot\left(\frac{1}{5}\right)^{n}-\frac{5 / 1}{8 \backslash 5} \cdot \frac{1}{5}$
(v) $\frac{15}{4}-\frac{3}{2}(3 n-2) \cdot\left(\frac{1}{3}\right)^{n}-\frac{9 / 1}{4 \backslash 3} \cdot \frac{1}{4}$
5. (i) 6
(ii) $\frac{21}{4}$
6. $\frac{2-(n+1) x^{n}+2 n x^{n+1}}{(1-x)^{2}}$
7. $n(2 n+1)$
8. $\frac{2}{1-x}+\frac{3 x\left(1-x^{n-1}\right)}{(1-x)^{2}}-\frac{(3 n-1) x^{n}}{1-x} \cdot \frac{2+x}{(1-x)^{2}}$

## EXERCISE 6.9

1. (i) $\frac{1}{19}$
(ii) $\frac{1}{11}$
2. (i) $-1,2, \frac{1}{2}, \frac{2}{7}, \frac{1}{5}$
(ii) $\frac{3}{22}, \frac{3}{32}, \frac{1}{14}, \frac{3}{52}, \frac{3}{62}$
3. $\frac{1}{13}$
4. -10
5. 67
6. -1
7. 3,6 or 6,3
8. 2,8 or 8,2
9. 19

## EXERCISE 6.10

1. (i) $\frac{n(n+1)(4 n+5)}{6}$
(ii) $\frac{n(n+1)(2 n+3)}{2}$
(iii) $n^{2}(n+1)$
(iv) $\frac{n(n+1)(n+4)(n+5)}{4}$
(v) $\frac{n(n+1)(n+2)(9 n+7)}{12}$
(vi) $\frac{2 n(n+1)(2 n+1)}{3}$
(vii) $\frac{n(n+1)\left(9 n^{2}+13 n+2\right)}{12}$
(ix) $\frac{n(n+1)(4 n+5)}{6}$
(x) $\frac{n(n+1)^{2}(n+2)}{12}$
2. (i) $-n(2 n+1)$
(ii) $\frac{n\left(4 n^{2}+15 n+17\right)}{36}$
3. (i) $n\left(n^{2}+4 n+5\right)$
(ii) $\frac{n\left(2 n^{2}+9 n-11\right)}{6}$
4. (i) $2 n\left(4 n^{2}+8 n+5\right)$
(ii) $\frac{4 n\left(2 n^{2}+3 n-2\right)}{3}$

## EXERCISE 6.11

1. Rs. 65 2. Rs. 239077.50 3. $5 \%$ 4. Rs. 173596 5. (a) 900 litres, (b) 200 weeks,
(c) 400 weeks 6. (a) 23.8 million
(b) $7+1.4 n$
(c) 21
7. (a) $100,80,64,51.2, \ldots$
(b) 482.4.(c) 500 8. Yes, Rs. 8000
9. Rs. 9468.22
10. 17 hours
11. 25 days
12. 1088
13. 7.2 seconds
14. 410.4 mA

## EXERCISE 7.1

1. (i) 90
(ii) 220
(iii) 20
(iv) $n+2$
2. (i) $\frac{(n+1)!}{(n-2)!}$
(ii) $\frac{n!}{(n-r)!}$
3. 5
4. 81
5. $\frac{(n+1)!(n+r+4)}{(r+2)!}$
6. 9

## EXERCISE 7.2

1. (i) 30240
(ii) 20
(iii) 5040
(iv) 720
2. (i) 9
(ii) 5 (iii) 10
3. (i) 720
(ii) 5040
(iii) 40320
4. 30
5. 325
6. 120
7. 100,36
8. 408
9. (i) 48
(ii) 72
10. 600,120
11. 24
12. 30240
13. 1440
14. 2880

# EXERCISE 7.3 

1. (i) 20160
(ii) 151200
(iii) 9979200
2. 10
3. 907200
4. 1260
5. (a) 5040
(b) 720
(c) 120
6. 2880
7. 90
8. 12612600
9. 725760
10. 131
11. 967680
12. 2880
13. 60
14. 60

## EXERCISE 7.4

1. (i) 1
(ii) 1
(iii) 120
(iv) 1140
2. (i) 2
(ii) 3
3. (i) 8,3
(ii) 6,2
6. 56
7. 120
8. 560
9. 171028000
10. (i) 1176
(ii) 280 (iii) 490 (iv) 56
11. 90,455
12. 16
13. 435
14. 11760
15. 56
16. 12376,8008
17. (i) 840
(ii) 1016
(iii) 1016
18. 108
19. (a) 94058496
(b) 4838400
20. (i) 518400
(ii) 14400

## EXERCISE 8.2

1. (i) $\frac{x^{4}}{64} \frac{3}{8} x^{3} \quad \frac{15}{4} \quad \frac{20}{x^{2}} \left\lvert\, \frac{60}{x^{6}} \frac{96}{x^{5}} \right.$
(ii) $128 a^{7} \quad 448 a^{5} x \quad 672 a^{3} x^{2} \quad 560 a x^{3} \quad 280 \frac{x^{4}}{a} \quad 84 \frac{x^{2}}{a^{2}} \quad 14 \frac{x^{6}}{a^{3}} \frac{x^{7}}{a^{7}}$
(iii) $\frac{a^{3}}{x^{3}} \quad \frac{6 a^{3}}{x^{2}} \left\lvert\, \frac{15 a}{x} \quad 20 \left\lvert\, \frac{15 x}{a} \quad \frac{6 x^{2}}{a^{2}} \right.$
(ii) 0.91267
(iii) 16.64966416
(iii) 9920.23968016
(iv) 40.84101
2. (i) $2 a^{4}+24 a^{2} x^{2}+8 x^{4}$
(ii) 724
3. (i) $16+32 x-8 x^{2}-40 x^{3}+x^{4}+20 x^{2}+2 x^{6}-4 x^{7}+x^{8}$
(ii) $1-4 x+10 x^{2}-16 x^{3}+19 x^{4}-16 x^{3}+10 x^{6}-4 x^{7}+x^{8}$
(iii) $4032 \frac{a^{4}}{x^{2}}$
(iv) $462 x^{2} y^{3}$
4. (i) $\frac{15309}{8}$
(ii) $\frac{(-1)^{n}(2 n)!}{(n!)^{2}}$
5. $\frac{15309}{8} x^{3}$
6. (i) -8064
(ii) $\frac{45}{4}$
(iii) 35
(iv) $\frac{221}{16} x^{6}$
(iii) $\frac{-692}{32} x$ and $\frac{77}{16 x}$
(iii) $2(-1)^{m} \frac{(2 m+1)!}{m!(m+1)!} x$ and $\frac{2}{3}(-1)^{m+1} \frac{(2 m+1)!}{m!(m+1)!} \frac{1}{x}$

## EXERCISE 8.3

1. (i) $1-\frac{1}{3} x+\frac{2}{9} x^{4}-\frac{14}{81} x^{2}+\cdots$ is valid if $|x|<1$
(ii) $2-\frac{3 x}{4} \frac{9 x^{3}}{64} \frac{27 x^{7}}{512}-\cdots$ is valid if $|x|<\frac{4}{3}$
(iii) $1-x+2 x^{2}-2 x^{3}+\ldots$ is valid if $|x|<1$
(iii) $1-x+2 x^{2}-2 x^{3}+\cdots$ is valid if $|x|<1$
(iv) $1+2 x+\frac{3}{2} x^{2}+2 x^{3}+\cdots$ is valid if $|x|<\frac{1}{2}$
2. (i) $(-1)^{n} \times 2 n$
(ii) $4 n$
3. $\frac{2}{\sqrt{5}}$

## EXERCISE 8.4

1. (i) 9.950
(ii) 1.010
(iii) 0.331
(iv) 0.935
2. Remainder $=1$
3. Remainder $=1$
4. (i) $21^{10}>19^{10}+20^{10}$
(ii) $31^{15}>29^{15}+30^{15}$
5. Remainder $=3$
6. 6
7. Rs. $12,616,000$
8. Rs. $2,928,200$
9. 28 matches

## EXERCISE 9.1

1. (i) Quotient $=3 x+2$, Remainder $=4$ (ii) Quotient $=x^{2}+14 x+25$, Remainder $=54$

(iii) Quotient $=x^{3}+x^{2}-2 x+1$, Remainder $=18$ (iv) Quotient $=5 x^{2}-3 x-18$, Remainder $=12 x+71$ (v) Quotient $=3 x^{2}+4 x-3$, Remainder $=-25 x+9$
(ii) 10 (iii) 5 (iv) 91 (v) 10
(ii) $x-2$ is a factor of $x^{2}-5 x+6$
(iv) $x-2$ is a factor of $x^{3}+x^{2}-7 x+2$
(iv) $x-2$ is a factor of $x^{3}+x^{2}-7 x+2$
(v) $x-3$ is not a factor of $x^{4}-3 x^{2}+x^{2}-x+1$
4. (i) $(x-2)(x-1)(x+3)$ (ii) $(x+4)(x-6)(x+2)$ (iii) $(x-2)(x+3)(x+1)(2 x+3)$
5. Quotient $=x^{2}-3 x^{2}-x+1$, Remainder $=1$ 6. $p=2, q=-1 \quad 7 . \quad k=1 \quad 8 . k=8$
9. $p \frac{-5}{2}, q \quad \frac{-1}{2}$ 10. $a=-8, b=-16$

# EXERCISE 9.2 

1. $26.25 \%$
2. 20 units, 2 units
3. $x=2,-1$
4. $x=-2,-1$
5. $x=-0.5,1$
6. $x=-0.5,0.8$, the system is stable.
7. $x=-0.5,-0.7$, the system is stable.

## EXERCISE 10.1

1. (i) $-\frac{\sqrt{3}}{2}$
(ii) 1
(iii) 2
(iv) 2
(v) $\frac{1}{\sqrt{3}}$
(vi) $\frac{-1}{2}$
2. (i) $-\cos 12^{\circ}$
(ii) $-\sin 12^{\circ}$
(iii) $\cos 27^{\circ}$ (iv) $\tan 33^{\circ}$ (v) $\sin 15^{\circ}$ (vi) $-\sin 39^{\circ}$ (vii) $-\cot 33^{\circ}$
(viii) $-\sin 21^{\circ}(\mathrm{ix})-\sin 30^{\circ}$

## EXERCISE 10.2

1. (i) $\frac{\sqrt{3}-1}{2 \sqrt{2}}$
(ii) $\frac{\sqrt{3}+1}{2 \sqrt{2}}$
(iii) $2-\sqrt{3}$
(iv) $\frac{\sqrt{3}+1}{2 \sqrt{2}}$
(v) $\frac{1-\sqrt{3}}{2 \sqrt{2}}$
(vi) $-2-\sqrt{3}$
2. (i) $-\frac{13}{85}$
(ii) $-\frac{84}{85}$
(iii) $\frac{13}{84}$
(iv) $\frac{77}{85}$
(v) $-\frac{36}{85}$
(vi) $-\frac{77}{36}$

The terminal arms of angles of measure and $\alpha+\beta$ and $\alpha-\beta$ are in III and II quadrants respectively.
10. (i) $\frac{33}{65},-\frac{56}{65}$
(ii) $-\frac{304}{425}, \frac{297}{425}$
15. (i) $25 \sin (\theta+\phi), \tan \phi=\frac{7}{24}$
(ii) $13 \sin (\theta-\varphi)$,
$\tan \varphi=\frac{5}{12}$
(iii) $\sqrt{2} \sin (\theta-\phi), \tan \phi=1$
(iv) $10 \sin (\theta-\varphi), \tan \varphi=\frac{3}{4}$
(v) $1 \sin (\theta+\varphi), \tan \varphi=\sqrt{3}$
(vi) $85 \sin (0-\phi)$, $\tan \phi=\frac{84}{13}$

## EXERCISE 10.3

1. (i) $\sin 2 \alpha=\frac{24}{25}, \cos 2 \alpha=\frac{7}{25}, \tan 2 \alpha=\frac{24}{7}$
(ii) $\sin 2 \alpha=\frac{24}{25}, \cos 2 \alpha=\frac{7}{25}, \tan 2 \alpha=\frac{24}{7}$
2. $\sin ^{4} \theta=\frac{3-4 \cos 2 \theta+\cos 4 \theta}{8}$
3. (i) $\sin 18^{\circ}=\frac{\sqrt{5}-1}{4}, \cos 18^{\circ}=\frac{\sqrt{10+2 \sqrt{5}}}{4}$
(ii) $\sin 36^{\circ}=\frac{\sqrt{10-2 \sqrt{5}}}{4}, \cos 36^{\circ}=\frac{\sqrt{5}+1}{4}$
(iii) $\sin 54^{\circ}=\frac{\sqrt{5}+1}{4}, \cos 54^{\circ}=\frac{\sqrt{10-2 \sqrt{5}}}{4}$

# Answers <br> (iv) $\sin 72^{\circ}=\frac{\sqrt{10+2 \sqrt{5}}}{4}, \cos 72^{\circ}=\frac{\sqrt{5}-1}{4}$ 

## EXERCISE 10.4

1. (i) $\sin 4 \theta+\sin 2 \theta$
(ii) $\sin 8 \theta-\sin 2 \theta$
(iii) $\frac{1}{2}(\sin 7 \theta+\sin 3 \theta)$
(iv) $\cos 5 \theta-\cos 9 \theta$
(v) $\frac{1}{2}(\sin 2 x-\sin 2 y)$
(vi) $\frac{1}{2}\left(\cos 4 x+\cos 60^{\circ}\right)$
(vii) $\frac{1}{2}\left(\cos 34^{\circ}-\cos 58^{\circ}\right)$
(viii) $\frac{1}{2}\left(\cos 90^{\circ}-\cos 2 x\right)$
2. (i) $2 \sin 4 \theta \cos \theta$
(ii) $2 \cos 6 \theta \sin 2 \theta$
(iii) $2 \cos \frac{9 \theta}{2} \cos \frac{3 \theta}{2}$
(iv) $-2 \sin 4 \theta \sin 3 \theta$
(v) $2 \cos 30^{\circ} \cos 18^{\circ}$ (vi) $2 \sin x \cos 30^{\circ}$

## EXERCISE 11.1

1. (i) even
(ii) neither even nor odd
(iii) even
(iv) neither even nor odd
(v) odd
(vi) odd
(vii) even
(viii) even
2. (i) $\frac{2 \pi}{5}$
(ii) $\frac{2 \pi}{7}$
(iii) $\frac{\pi}{3}$
(iv) $2 \pi$
(v) 40
(vi) $5 \pi$
(vii) $\frac{4 \pi}{3}$ (viii) $\frac{2}{7}$
(ix) 30
(x) $\frac{4 \pi}{7}$ (xi) $30 \pi$

## EXERCISE 11.2

1. (i)
[Image removed]

[Image removed]

$$
y=\sin \frac{x}{2} x
$$

[Image removed]

# EXERCISE 11.3 

1. (i) $\mathrm{Max}=4, \mathrm{Min}=2$
(ii) $\mathrm{Max}=4, \mathrm{Min}=2$
(iii) $\mathrm{Max}=\frac{3}{2}, \mathrm{Min}=\frac{-1}{2}$
(iv) $\mathrm{Max}=\frac{5}{2}, \mathrm{Min}=\frac{1}{2}$
(v) $\mathrm{Max}=4, \mathrm{Min}=-2$ (vi) $\mathrm{Max}=3, \mathrm{Min}=-1$ (vii) $\mathrm{Max}=\frac{1}{8}, \mathrm{Min}=\frac{1}{12}$ (viii) $\mathrm{Max}=\frac{1}{4}, \mathrm{Min}=\frac{1}{10}$
(ix) $\mathrm{Max}=\frac{1}{2}, \mathrm{Min}=\frac{1}{8}$
2. (a) Max. temperature $=21.5^{\circ} \mathrm{C}, \mathrm{Min}$ : temperature $=8.5^{\circ} \mathrm{C}$
(b) Temperature at $9 \mathrm{a} . \mathrm{m} .=8.89^{\circ} \mathrm{C} \quad$ 3. distance $=36.78 \mathrm{~m}$ 4. height $=30.92 \mathrm{~m}$
3. (a) $h(t)=-30 \cos \left(\frac{\pi}{40} t\right)+36$ (b) 66 feet (c) 63.72 feet
4. (a) 2.7 m (b) 0.3 m
(c) $\frac{2}{3}$ second
(d) 0.05 second
5. (a) $h(t)=28-20 \cos \left(\frac{\pi}{60} t\right)$
(b) 28 feet
(c) 37.87 s and 82.13 s
6. (a) $66.07^{\circ} \mathrm{F}$
(b) 14 hr or 2 p.m.
(c) $72^{\circ} \mathrm{F}$
7. (a) 65000
(b) 80000

## EXERCISE 12.1

1. (i) 2
(ii) 0
(iii) divergent
(iv) $\frac{1}{2}$
2. (i) 10
(ii) 5
(iii) 4
(iv) 0
(v) 0
(vi) $\frac{13}{4}$
3. (i) 2
(ii) $\frac{1}{4}$
(iii) -12 (iv) 0
(v) 0
(vi) -4
(vii) 2
(viii) $\frac{1}{2 \sqrt{x}}$
(ix) $\frac{\pi}{m} a^{n \rightarrow 4}$
4. (i) 5
(ii) $\frac{\pi}{180}$
(iii) 0
(iv) $\sqrt{2}$ (v) $\frac{b^{2}-a^{2}}{2}$
(vi) 2
(vii) 2
(viii) $\frac{a^{2}-b^{2}}{c^{2}-d^{2}}$
(ix) $\frac{3}{2}$
(x) $6-\log 3$
(xi) $2 \log 2$
5. (i) $e^{2}$
(ii) $\sqrt{e}$
(iii) $\frac{1}{e}$
(iv) $e^{\frac{1}{2}}$
(v) $e^{4}$
(vi) $e^{8}$
(vii) $e^{5}$
(viii) $\frac{a-b}{a b}$
(ix) $\frac{1}{e}$
(x) -1
(xi) 1
(xii) $e^{2}$

## EXERCISE 12.2

1. (i) -2 (ii) 0 (iii) 0
2. (i) $f$ is continuous at $x=2$ (ii) $f$ is discontinuous at $x=1$

3. (i) $f$ is continuous at $x=2$ (ii) $f$ is discontinuous at $x=-2$ 4. $c=-1$
4. (i) $m=1, n=3$ (ii) $m=4$
5. $k=\frac{1}{6}$
6. $f(x)$ is discontinuous at $x=1$.

# EXERCISE 12.3 

1. 0
2. 100,000
3. 500
4. (i) 10
(ii) 0
5. (i) $\infty$
(ii) 82.44
5. yes
6. (i) $16.18 \%$
(ii) 134.99
7. yes

## EXERCISE 13.1

1. (i) $4 x$
(ii) $\frac{-1}{2 \sqrt{x}}$
(iii) $-\frac{1}{2} x^{3 / 2}$
(iv) $2 x-3$
2. (i) $\frac{1}{4 \sqrt{2}}$
(ii) $-\frac{1}{4 \sqrt{2} a^{3 / 2}}$
3. (i) $\frac{1}{3}$
(ii) $2 x+2$
4. (i) $\frac{-6}{(3 x-2)^{3}}$
(ii) $10(2 t+3)^{4}$
(iii) $7 a(a w+b)^{4}$
5. $8, y=8 x+13$
6. $y=7 x+4$
7. $(1,0), y=x-1$
8. 8
9. $\frac{1}{6}, 6 y=x+9$
10. (i) $28 \mathrm{~km} / \mathrm{h}$
(ii) $13 \mathrm{~km} / \mathrm{h}$
11. 0
12. $8^{x} \mathrm{c} / \mathrm{hr}$
13. (i) not differentiable
(ii) not differentiable

## EXERCISE 13.2

1. (i) $4 x^{3}+6 x^{2}+2 x$
(ii) $-3\left(\frac{1}{x^{2}}+\frac{1}{x^{3 / 2}}\right)$
(iii) $\frac{8}{(2 x+1)^{2}}$
(iv) $\frac{1-3 x}{2 \sqrt{x}}$
(v) $1-2 x^{-3}+x^{-6 / 2}$
(vi) $8-2 x$
(vii) $\frac{2 x\left(x^{2}+1\right)\left(x^{2}-3\right)}{\left(x^{2}-1\right)^{2}}$
(vii) $\frac{-8 x}{\left(x^{2}-3\right)^{2}}$
(ix) $\frac{x+2}{\left(x^{2}+1\right)^{3 / 2}}$
(x) $\frac{-a}{\sqrt{a-x(a+x)^{3 / 2}}}$
(xi) $\frac{-2 x}{\sqrt{x^{2}+1}\left(x^{2}-1\right)^{3 / 2}}$
2. $\frac{3 x^{2}-2 x^{3 / 2}-3 x+2}{2 \sqrt{x}(\sqrt{x}-1)^{2}}$
3. $\frac{x^{3}-3 x^{2}+3 x-1}{2 \sqrt{x}\left(x^{3 / 2}-x^{1 / 2}\right)^{2}}$

## EXERCISE 13.3

1. $v=15 t^{2}-6 t+1$
2. Maximum Stress $=100$, Rate of change $=0$
3. (i) $P(x)=-10 x^{2}+700 x-2000$
(ii) Rs. 400
4. (i) 2940
(ii) 27440
5. (i) $152 \mathrm{~m} / \mathrm{s}$
(ii) $96 \mathrm{~m} / \mathrm{s}^{2}$
6. (i) $72 \mathrm{~km} / \mathrm{h}$
(ii) $-12 \mathrm{~km} / \mathrm{h}^{2}$
7. $292 \mathrm{~Pa} / \mathrm{m}$
8. 191686.6 units $/ \mathrm{m}$

## EXERCISE 14.1

1. (i) $1-91$
(ii) $131-21-22 k$
(iii) $\sqrt{273}$
2. (i) $7 ; \frac{3}{7}, \frac{-2}{7}, \frac{6}{7}$
(ii) $6 ; \frac{-2}{3}, \frac{2}{3}, \frac{1}{3}$
(iii) $10 ; \frac{-3}{5}, \frac{4}{5}, 0$
3. $t=\frac{1 \pm \sqrt{17}}{2}$
4. $-\frac{1}{9} 1+\frac{4}{9} 1-\frac{8}{9} k$
5. $\frac{171-121-16 k}{\sqrt{689}}$
6. (i) $\frac{15}{\sqrt{26}} 1+\frac{20}{\sqrt{26}} 1-\frac{5}{\sqrt{26}} k$ (ii) $-\frac{7}{\sqrt{3}} 1+\frac{7}{\sqrt{3}} 1+\frac{7}{\sqrt{3}} k \quad 7 . x=-3, y=-5$ 9. (a) $\frac{2}{3} 1-\frac{4}{3} 1+\frac{4}{3}$ $k$ and $\frac{2}{3} 1+\frac{4}{3} 1-\frac{4}{3} k$ (b) $a=-3$ (c) $-\frac{5 i}{\sqrt{14}}+\frac{10 j}{\sqrt{14}} \frac{15 k}{\sqrt{14}}$ (d) $a=-\frac{3}{2}, b=\frac{1}{2}$

10. $10 \sqrt{179}$ kilometers
11. (i) $-\frac{6}{7}, \frac{3}{7}, \frac{2}{7}$
(ii) $\frac{4}{3 \sqrt{5}}, \frac{2}{3 \sqrt{5}},-\frac{\sqrt{5}}{3}$
(iii) $\frac{2}{7}, \frac{3}{7}, \frac{6}{7}$
11. Only the triple (iii) $45^{\circ}, 60^{\circ}, 60^{\circ}$ satisfies the condition for direction angles of a single vector.

# EXERCISE 14.2 

1. (i) $\frac{2}{\sqrt{14}}$ (ii) $\frac{-1}{\sqrt{1558}}$
2. $\theta=60$
3. $\theta=90$
4. (i) Projection of $\underline{a}$ along $\underline{b}:-\frac{4}{7} \underline{a}$; Projection of $\underline{b}$ along $\underline{a}:-\frac{8}{21} \underline{b}$
(ii) Projection of $\underline{a}$ along $\underline{b}: \frac{5}{29} \underline{a}$; Projection of $\underline{b}$ along $\underline{a}: \frac{5}{3} \underline{b}$
5. (i) 3 (ii) 1 or $-\frac{3}{2}$
6. 2 or -3 13. 56 units 14. 32 units 15. 102 units 16. $\frac{198}{\sqrt{26}}$ units

## EXERCISE 14.3

1. (i) $a \times \underline{b}=-3 \underline{j}-3 k ; \underline{b} \times \underline{a}=3 \underline{j}+3 \underline{k}$
(ii) $a \times \underline{b}=5 \underline{j}+3 \underline{j}-7 \underline{k} ; \underline{b} \times \underline{a}=-5 \underline{j}-3 \underline{j}+7 \underline{k}$
(iii) $\underline{a} \times \underline{b}=-7 \underline{j}-7 \underline{j} ; \underline{b} \times \underline{a}=7 \underline{j}+7 \underline{j}$ (iv) $\quad \underline{a} \times \underline{b}=3 \underline{j}-6 \underline{k} ; \underline{b} \times \underline{a}=-3 \underline{j}+6 \underline{k}$
2. (i) $\frac{21 \underline{j}-9 \underline{j}-11 \underline{k}}{\sqrt{643}} ; \sin \theta=\frac{\sqrt{643}}{\sqrt{644}}$
(ii) $\frac{-7 \underline{j}+2 \underline{j}+5 \underline{k}}{\sqrt{78}} ; \sin \theta=\frac{\sqrt{78}}{\sqrt{87}}$
(iii) $\frac{\underline{j}-\underline{k}}{\sqrt{2}} ; \sin \theta=\frac{2 \sqrt{2}}{3}$
(iv) $\frac{13 \underline{j}+\underline{j}+22 \underline{k}}{\sqrt{654}} ; \sin \theta=\frac{\sqrt{654}}{\sqrt{735}}$
3. (i) $\frac{3 \sqrt{26}}{2}$ square units
(ii) $\frac{5 \sqrt{2}}{2}$ square units

4 (i) $\sqrt{237}$ square units
(ii) $\sqrt{190}$ square units
5. $a=\frac{21}{5}, b=\frac{12}{5}$
6. (i) Parallel vectors: $\underline{u}$ and $\underline{w}$; Perpendicular vectors: No
(ii) Parallel vectors: $\underline{u}$ and $\underline{w}$; Perpendicular vectors: $\underline{u}$ and $\underline{v} ; \underline{v}$ and $\underline{w}$
13. $48 \underline{j}-4 \underline{j}+30 \underline{k}$
14. $-14 \underline{j}-14 \underline{k}$
15. $3 \underline{j}+3 \underline{j}+3 \underline{k}$
16. $15 \underline{j}-15 \underline{j}-15 \underline{k}$

## EXERCISE 14.4

1. (i) 25 cubic units (ii) 14 cubic units (iii) 10 cubic units 4. (i) $\frac{5}{2}$ (ii) $\pm 1$
2. (a) (i) 4
(ii) 3
(iii) 1
(iv) 0
3. (i) $\frac{\underline{u}}{3}$ cubic units
(ii) $\frac{2}{3}$ cubic units
4. $\frac{301}{\sqrt{1630}}$
5. $150 \underline{j}-100 \underline{k}$ (in pound feet)
6. $\sqrt{41}$ meters
7. Rs. 532500 , which is the total revenue from the sales of all items.
8. $-20 \underline{j}+110 \underline{j}+50 \underline{k} \mathrm{Nm}$
9. (a) $[500,300,200],[500,400,2000]$
(b) Rs. 770000
