---
title: "Projects"
permalink: /projects/
author_profile: true
use_math: true
title: "Projects"
excerpt: "Projects"
---

I have outlined my non-research projects in this page. My research work can be found [here](https://kc1729.github.io/research/)

Technical Projects:
===
1.  **Deep Reinforcement Learning for Atari games |  Summer Internship** (May '16 - July '16) <br/>
    *Guide : [Prof. Paul Weng](https://weng.fr/index.html), [UM-SJTU Joint Institute](http://umji.sjtu.edu.cn/)* <br/>
    Reviewed the code of Google DeepMind for choosing optimal actions while playing Atari Games and ran experiments on  variants of its  Deep Q-Network (DQN) by incorporating ideas like  Double DQN and  Duelling network architectures.  Binarized the neural network estimating the Q-function to speed up learning and save on memory, leading to a  3-fold decrease in memory usage compared to original code.<br/>
    
2.  **Mathematics of Deep Learning** (Jan '18 - April '18) <br/>
    *Guide : [Prof. Vivek Borkar](https://www.ee.iitb.ac.in/web/faculty/homepage/borkar), EE Department, IIT Bombay* <br/>
    Surveyed the recent literature on the mathematics underlying regularization in deep neural networks and how stochastic gradient descent (SGD) performs variational inference. Reviewed theoretical analysis of Entropy-SGD which provably outperforms the classical SGD algorithm by converging to wider valleys.
    \[[Report](https://kc1729.github.io/files/EE763_140070014.pdf)\]
    
3.  **Risk Constrained Markov Decision Processes** (Jan '17 - April '17) <br/>
    *Guide : [Prof. Vivek Borkar](https://www.ee.iitb.ac.in/web/faculty/homepage/borkar), EE Department, IIT Bombay* <br/>
    Surveyed the literature on risk aware markov decision processes and corresponding reinforcement learning algorithms, namely risk-aware versions of value iteration, policy gradient and actor-critic algorithms.
    \[[Report](https://kc1729.github.io/files/EE736_140070014.pdf)\]
        
4.  **Johnson-Lindenstrauss Lemma and its Applications** (Jul '17 - November '17) <br/>
    *Guide : [Prof. Sharayu Moharir](https://sites.google.com/site/sharayumoharir/), EE Department, IIT Bombay* <br/>
    Studied and presented various probabilistic proofs and applications of Johnson-Lindenstrauss lemma which uses random projections to find low-distortion embeddings of points into a low-dimensional space.
    
5.  **RF Transmit Dongle for Communications Lab** (Jan '17 - April '17) <br/>
    *Guide : [Prof. Shalabh Gupta](https://www.ee.iitb.ac.in/wiki/faculty/shalabh), EE Department, IIT Bombay* <br/>
    Prototyped a low cost, portable transmit dongle compatible with GNURadio which transmits signals with sampling rate upto 3 MSamp/sec using AFE7070 modulator, Hitachi SRAM and a 0808 DAC circuit. Generated digital samples using custom-made GNURadio block, enabled data transmission to FPGA using UART and sent the signal to AFE7070 Modulator after digital to analog conversion.
    
6.  **Microprocessor Design - Pipelined Implementation** (July '16 - November '16) <br/>
    *Guide : [Prof. Virendra Singh](https://www.ee.iitb.ac.in/~viren/), EE Department, IIT Bombay* <br/>
    Designed and implemented a working microprocessor with 19 instructions using a Pipelined design architecture on the Deo Nano Board in VHDL. Used the NMRU (Not Most Frequently Used) scheme and implemented a fully associative cache so as to improve the performance.
    
7.  **8-PSK Costas Loop GNURadio Block** (July '16 - November '16) <br/>
    *Guide : [Prof. Shalabh Gupta](https://www.ee.iitb.ac.in/wiki/faculty/shalabh), EE Department, IIT Bombay* <br/>
    Designed a custom GNURadio block using Python which performs carrier frequency recovery from phase modulation signals for small frequency errors of the order 10−1 hertz and noise with amplitude around 2 % of the signal amplitude. Analysed the Gain margin and Phase margin for the custom block.
    
    
8.  **Pyraminx Utility Kit** (Jan '15 - April '16) <br/>
    *Guide : [Prof. Kavi Arya](https://https://www.it.iitb.ac.in/~kavi/), CSE Department, IIT Bombay* <br/>
    Implemented the BFS algorithm and AVL trees to derive the  optimal solutions of a Pyraminx, a tetrahedron Rubiks Cube style puzzle. Used Allegro, a C++ framework,  to design an interface to help solve pyraminx optimally, find cube algorithms and generate solve analysis. Designed an Android app implementing image processing techniques to read pyraminx configurations and send it to a Java server.
