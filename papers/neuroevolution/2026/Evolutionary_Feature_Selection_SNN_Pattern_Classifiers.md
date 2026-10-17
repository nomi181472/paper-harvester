Title: Evolutionary Feature Selection for Spiking Neural Network Pattern Classifiers

URL Source: https://arxiv.org/html/2604.26654

Markdown Content:
###### Abstract

This paper presents the application of the biologically realistic JASTAP neural network model to classification tasks. The JASTAP neural network model is presented as an alternative to the basic multi–layer perceptron model. An evolutionary procedure previously applied to the simultaneous solution of feature selection and neural network training on standard multi–layer perceptrons is extended with JASTAP model. Preliminary results on IRIS standard data set give evidence that this extension allows the use of smaller neural networks that can handle noisier data without any degradation in classification accuracy.

## I Introduction

Classification of patterns is important to many data mining processes. Among possible classifiers, artificial neural network classifiers have proven to be one of the most robust classification systems. Their capability to deal with noisy input patterns, to handle both noisy and continuous value data did prove to be an essential tool for classification and prediction[[1](https://arxiv.org/html/2604.26654#bib.bib1)].

This paper presents a research aiming to replacing the basic perceptron model[[5](https://arxiv.org/html/2604.26654#bib.bib5)] to the neural realistic JASTAP model[[6](https://arxiv.org/html/2604.26654#bib.bib6)], in some problems were a better representation of recurence and context may be needed. JASTAP model implements biologically plausible neural networks in a well parameterized model that can be statistically related[[13](https://arxiv.org/html/2604.26654#bib.bib13)]. Since the usual simplifications for other spiking models[[7](https://arxiv.org/html/2604.26654#bib.bib7)] are not done a priori, we can keep all the flexibility known in biological neurons. On the same time, since parameters can also be predefined in advance (giving rise to more simple models) JASTAP proves as a very powerful new way of representing both model knowledge and experience. This way, only needed features can be activated in the model. A first demonstrative study on the use of this new kind of artificial neural network for classification tasks is presented on IRIS dataset.

Standard backpropagation learning[[5](https://arxiv.org/html/2604.26654#bib.bib5)] on JASTAP neural networks (and on simpler spiking models in general) is still an open issue (mainly due to the different weights that need to be adjusted and to cyclic connections). So, a more generic and powerful learning method is used: we have incorporated in JASTAP the evolutionary learning model of FeaSANNT[[8](https://arxiv.org/html/2604.26654#bib.bib8)]. FeaSANNT is an evolutionary procedure for simultaneous solution of the two combinatory search problems of feature selection and parameter learning in artificial neural network classifier systems. FeaSANNT was already successfully applied to feature selection on traditional artificial neural network pattern classifiers[[8](https://arxiv.org/html/2604.26654#bib.bib8)]. In this paper we extend previous work by applying the JASTAP model to the same type of classification problems.

An additional motivation for this work relies on the need to encode background information and recurence in neural networks. Indeed, recent work presents the so called neuro–symbolic networks[[2](https://arxiv.org/html/2604.26654#bib.bib2)]. Based on a logic representation, these systems provide both simple ways to represent predicate logic programs as MLP neural networks[[3](https://arxiv.org/html/2604.26654#bib.bib3)] as well as to represent neural networks as rule base systems[[2](https://arxiv.org/html/2604.26654#bib.bib2)]. Unfortunately, providing simple and adjustable structures for encoding previous knowledge or algorithms in a neural network is a difficult task (e.x. Siegelmann’s Neural Automata and Analog Computational Complexity article in [[4](https://arxiv.org/html/2604.26654#bib.bib4)]). Due to the simple model for each unit, basic multilayer perceptron models often need many units (most of times organized in more than one layer). Also, the simple MLP (and the related popular backpropagation learning algorithm[[5](https://arxiv.org/html/2604.26654#bib.bib5)]), can not handle cyclic connections. The well known usage of MLPs as universal approximatiors can only be achieved by means of enlarging the hidden layer neurons as needed (e.x. Kürková’s Universal Approximators article in [[4](https://arxiv.org/html/2604.26654#bib.bib4)]). As a result, in problems where context or time representation is needed, repetive iterations can not be used, because there are no recursive structures in MLP. Spiking neurons in general and JASTAP model in particular may present a solution for this problem.

The remaining of this paper is organized as follows. Section [II](https://arxiv.org/html/2604.26654#S2 "II JASTAP ‣ Evolutionary Feature Selection for Spiking Neural Network Pattern Classifiers") presents the JASTAP spiking neural model. Then the learning procedure used is presented in section [III](https://arxiv.org/html/2604.26654#S3 "III FeaSANNT ‣ Evolutionary Feature Selection for Spiking Neural Network Pattern Classifiers"). The changes made to adapt this procedure and some advantages and properties specific for JASTAP networks are described in section [IV](https://arxiv.org/html/2604.26654#S4 "IV Using JASTAP NN model for Pattern Classification ‣ Evolutionary Feature Selection for Spiking Neural Network Pattern Classifiers"). Experimental results are presented in section [V](https://arxiv.org/html/2604.26654#S5 "V Results and Comparisons ‣ Evolutionary Feature Selection for Spiking Neural Network Pattern Classifiers"). Finally, the contributions of this work are presented in section [VI](https://arxiv.org/html/2604.26654#S6 "VI Conclusions ‣ Evolutionary Feature Selection for Spiking Neural Network Pattern Classifiers").

## II JASTAP

### II-A JASTAP As a Spiking Neuron Model

JASTAP 1 1 1 pronounced as Yastap model aims to simulate some biologically realistic functions of neural networks[[6](https://arxiv.org/html/2604.26654#bib.bib6)]. JASTAP belongs to the family of spiking models. Formal spiking neuron models in general work with temporal coding with mostly biologically relevant action potentials. Spiking models can also perform complex non–linear classification[[9](https://arxiv.org/html/2604.26654#bib.bib9)]. This can be achieved with less units (spiking neurons) than with classical rate–coded networks (please see section [V-C](https://arxiv.org/html/2604.26654#S5.SS3 "V-C Results ‣ V Results and Comparisons ‣ Evolutionary Feature Selection for Spiking Neural Network Pattern Classifiers")).

In this section we briefly present JASTAP model[[6](https://arxiv.org/html/2604.26654#bib.bib6)] and the parameters used for easier adaptation of this model to classification tasks. More details on the JASTAP model can be found in[[6](https://arxiv.org/html/2604.26654#bib.bib6)].

### II-B Model Description

A JASTAP model is an artificial NN, which consists of JASTAP neurons as the basic elements. A neuron is described with:

*   •
set of synapses As it is usual in any neural network model, an JASTAP neuron is interconnected with its environment by one or more synaptic inputs and a single output (axon). The output can be connected with one or more neuron synapses in the network.

For each synapse we consider:

    *   –
input — can be internal (connected with axon of other neuron) or external (from the outer environment).

    *   –
shape of postsynaptic potential (PSP) prototype — Biological neuron waveform evoked by a spike arriving at a synapse is described in JASTAP model by

\mathrm{PSP}(t)=k\cdot{\left(1-\mathrm{e}^{-\frac{t}{t_{1}}}\right)}^{2}\cdot\mathrm{e}^{-\frac{2t}{t_{2}}}(1) 
The waveform inter alia (controlled by parameters t_{1} and t_{2}) emulates whether the synapse is located on a soma or on a dendritic tree. t_{1} and t_{2} can vary from synapse to synapse. They determine the potential decay. For example, [[10](https://arxiv.org/html/2604.26654#bib.bib10)] mentions t_{1}=0.3\,\mathrm{ms} and t_{2}=2.7\,\mathrm{ms}. As the neuron carries out the time–and–space summation of the input potentials and due to time discretisation during simulation, a more moderate decay can cause more sophisticated information processing. Therefore, we used t_{1} up to 5\,\mathrm{ms} and t_{2} up to 15\,\mathrm{ms} (please see figure[1](https://arxiv.org/html/2604.26654#S2.F1 "Figure 1 ‣ 2nd item ‣ 1st item ‣ II-B Model Description ‣ II JASTAP ‣ Evolutionary Feature Selection for Spiking Neural Network Pattern Classifiers")).

Figure 1: Postsynaptic potential (PSP) with different waveform inter alia.

    *   –
latency — the time delay of the synaptic transmission and the axonal conduction. In other words, synapse is silent for the latency time before it starts to translate the input impulse into an action potential.

    *   –
synaptic weight (SW) — a value from \left\langle-1,1\right\rangle that represents the strength of the synaptic input. An excitatory \mathrm{PSP} is distint from a synapse with a positive SW and an inhibitory \mathrm{PSP} from a synapse with a negative SW.

    *   –
plastic changes — Depending of the synapse type, SW can be influenced by some mechanisms, for instance Hebbian learning or heterosynaptic presynaptic mechanism. In future this can be used to enable online learning. In this work this feature of the model is not used, because the learning during information processing phase is not our goal.

*   •instantaneous membrane potential (MP) — a quantity within the \left\langle-1,1\right\rangle range, determined as the sum of \mathrm{PSP}s limited by the non–linear function (figure[2](https://arxiv.org/html/2604.26654#S2.F2 "Figure 2 ‣ 2nd item ‣ II-B Model Description ‣ II JASTAP ‣ Evolutionary Feature Selection for Spiking Neural Network Pattern Classifiers"))

\mathrm{MP}(t)=\frac{2}{\pi}\cdot\mathrm{atan}\left(\sum\nolimits_{\mathrm{synapses}}\mathrm{PSP}(t)\right)(2) 

Figure 2: Limiting non–linear function

*   •
threshold — \theta, a value from \left\langle 0,1\right\rangle — that determines the limit for firing.

*   •spike frequency — the spike frequency is restricted by the absolute refractory period. This is managed by setting minimum I_{\min} and maximum I_{\max} inter–spike interval for the firing pattern. The standard value we use is I_{\min}=1\,\mathrm{ms} for the lowest and I_{\max}=10\,\mathrm{ms} for the highest value. The actual inter–spike interval I_{a} is determined as:

I_{a}=I_{\max}-(I_{\max}-I_{\min})\cdot\frac{2}{\pi}\cdot\mathrm{atan}\left(\frac{\mathrm{MP}-\theta}{1-\mathrm{MP}}\right)(3) 
The spike frequency condition does not allow the neuron to fire sooner, even if the MP exceeds the threshold.

### II-C Tasks Where JASTAP Has Already Succeeded

JASTAP was primarily designed to model real information flow in human brain. Until now, most experiments with JASTAP intend to prove this behavior. On one hand, [[11](https://arxiv.org/html/2604.26654#bib.bib11)] shows that the JASTAP networks can handle (even noised) information coded in temporal patterns. On the other hand, [[12](https://arxiv.org/html/2604.26654#bib.bib12)] shows its ability to recognize and distinguish different spike rates. This is particularly interesting since the standard MLP weights can be seen as the mean spiking rate concept.

JASTAP model also presents several capabilities that are related with the Gamma distribution [[13](https://arxiv.org/html/2604.26654#bib.bib13)]. Gamma distribution was chosen for experiments because of biological evidence of its plausibility[[14](https://arxiv.org/html/2604.26654#bib.bib14)]. The results shown that the JASTAP models are able to make decisions about features (mean rate, coefficient of variation) of Gamma distribution even with very few neuron units. Moreover[[13](https://arxiv.org/html/2604.26654#bib.bib13)] explored evolved networks and described at low–level how the actual decisions are made.

## III FeaSANNT

### III-A What Is FeaSANNT?

FeaSANNT is an evolutionary procedure for simultaneous solution of the two combinatorial search problems of feature selection and parameter learning for artificial neural network classifier systems[[8](https://arxiv.org/html/2604.26654#bib.bib8)].

One of the major problems in the use of ANNs is to train the frequently large set of parameters (usually, the connection weights). Most of ANN weight training procedures are based on gradient descent of the error surface, so they are prone to sub–optimal convergence to local minima. Global search techniques such as evolutionary algorithms (EAs) are known to produce more robust results when pursuing multi–objective optimization in large, noisy, multimodal and deceptive search spaces, such as this one.

### III-B Feature Selection in an Embedded Approach

Feature selection can be regarded as a search problem in the discrete space of the subsets of data attributes. Unfortunately, due to the often large set of attributes and their interactions, selecting the optimal feature vector is usually difficult and time consuming. Once again, the search space is noisy, complex, nondifferentiable, multimodal and deceptive and the results are strongly related to the type of classifier system used. However, as pattern classification is based on the information carried by the feature vector, feature selection has a crucial impact on the classifier accuracy, learning capabilities and size.

FeaSANNT implements an embedded approach in an evolutionary feature selection paradigm. The search is guided by using GAs for learning how to mask inputs. This paper reports on the extension of FeaSANNT model to handle JASTAP Spiking Neural Networks. FeaSANNT’s embedded approach was found as particularly useful when a genetic algorithm was used for evolution as well as for learning. This way we were able to use the global nature of the evolutionary search to avoid being trapped by sub–optimal peaks of performance while learning both the best set of features, neuron threshold, synapse weights and synapse latencies.

### III-C What has been already done?

Previous experiments with FeaSANNT [[8](https://arxiv.org/html/2604.26654#bib.bib8)], shown that the simultaneous evolution of the input vector and the ANN weights allows significant saving of computational resources. FeaSANNT algorithm was applied on the popular multi–layer perceptron classifier. Also several experiments were preformed on six real–world numerical data sets that gave accurate and robust learning results. Significant reduction of the initial set of input features was achieved in most of the benchmark problems considered. Examination of the evolution curves revealed selection of the optimal feature vector takes place at an initial stage of the search. FeaSANNT seemed also to compare well with other classification algorithms in the literature. However, the proposed algorithm entails lower computational costs due to the embedded feature selection strategy.

## IV Using JASTAP NN model for Pattern Classification

### IV-A Expected Benefits

Expected benefits of spiking models, like JASTAP for pattern recognition (together with feature selection), include:

##### Smaller network structures

As stated previously, when compared to MLP, JASTAP neurons should require a smaller number of units. There is already some evidence that the decrease in number of neuron units can be seen even in the simple XOR problem[[9](https://arxiv.org/html/2604.26654#bib.bib9)] when using Spike Response Model[[15](https://arxiv.org/html/2604.26654#bib.bib15)].

##### Noise filtering

In[[11](https://arxiv.org/html/2604.26654#bib.bib11)] authors point out that JASTAP is able to extract information with _background spiking noise_. In section[V](https://arxiv.org/html/2604.26654#S5 "V Results and Comparisons ‣ Evolutionary Feature Selection for Spiking Neural Network Pattern Classifiers") it will shown how much noise JASTAP model can bear when applied to the IRIS dataset. We will be especially interested in processing data with Gamma noise, as this kind of noise that is biologically relevant[[14](https://arxiv.org/html/2604.26654#bib.bib14)].

##### Results amenable to analysis

A smaller number of units and detailed processing (temporal coding instead of rate coding) give us a chance to take an insight to internal operations at the level of synapses. Simply speaking, we will try to _decode_ what is the evolved network actually doing.

### IV-B Encoding Variables into Spike–Time Patterns

Encoding processed data into time patterns is still an open issue even for Neurophysiology. For example, it is not clear if the temporal[[16](https://arxiv.org/html/2604.26654#bib.bib16)] or rate coding representations play a crucial role in information processing[[17](https://arxiv.org/html/2604.26654#bib.bib17)].

We found a first mention to this issue in [[9](https://arxiv.org/html/2604.26654#bib.bib9)]. Authors used _receptive fields_ to transform real–world data into patterns. Although this approach can be neurologically plausible, for our (FeaSANNT) purposes it was decided to use a _repetitive_ encoding when the same inter–spike interval representing the data value is repeated as an input to input neuron. When the mask element is applied to a particular input, that neuron just receives an empty input train.

Every input is associated with one input neuron as an external synapse. Spike potentials for input neurons are precalculated from input data in such a way that the inter–spike lengths are linearly dependent on the data value (in the range of 5–15\,\mathrm{ms}). If no noise is taken into account interspike intervals corresponding to one input train are the same. When we test the noise handling, each interspike interval receives a value chosen from the Gamma distribution. This kind of noise is considered as more biologically relevant (rather than applying noise to a particular value) because it indicates cumulative noise during information processing over several neurons (fig.[3](https://arxiv.org/html/2604.26654#S4.F3 "Figure 3 ‣ IV-B Encoding Variables into Spike–Time Patterns ‣ IV Using JASTAP NN model for Pattern Classification ‣ Evolutionary Feature Selection for Spiking Neural Network Pattern Classifiers")).

![Image 1: Refer to caption](https://arxiv.org/html/2604.26654v1/x3.png)

Figure 3: Example of encoding data to temporal code: first iris–setosa training example (i.e. [5.1,3.5,1.4,0.2] scaled to [7.2, 11.3, 5.7, 5.4]). Each row represents an input to 1 of 4 input neurons. Data are scaled to 5–15\,\mathrm{ms} and repeated over time period of 300\,\mathrm{ms}. Every interspike–interval is noised with \pm 1\,\mathrm{ms} of Gamma noise. 

Decoding to output can be simple. The following method is used: Some neurons in the network are designated as the _output_ neurons. When any of the output neurons fire, they are taken as a _hot–spot_ network decision. The meaning of the decision is task–dependent. Thereafter the simulation in progress can be stopped, because the subsequent activity has no impact on the final decision.

### IV-C Designing Fitness Function for JASTAP Classification

During the tests preformed the selection of fitness function was a crucial step when evolving (recurrent) JASTAP networks. The fitness function was crucial not only for the number of iterations for evolution (i.e. the time the network took to learn), but also in effectivity of learning.

In the first place, the simple successful ratio based fitness functions gave very poor results. A problem with these functions is that they cannot distinguish between networks with no response from those which are able to fire (even if not correctly). Furthermore local minima are common in these cases. This is the consequence of the emergence of the individuals responding to all inputs in the same way. To avoid such problems it was created a fitness function that favors the following criteria:

*   •
_early_ or non–silent _responses_ on input pattern can be classified as incorrect.

*   •
_hetereogeneousness_: A network responding (correctly) to many patterns from various classes is better that than a network that can correctly respond to only one. (With same overall ratio).

*   •
_selectivity_: we should evaluate with higher fitness networks responding mostly correctly to one class, even if responding randomly (or not responding) to the other classes. Indeed these networks exhibit selectivity to some class are better that networks which respond to all patterns in the same way (this is often case, when a population is initialized with random weights).

*   •
For datasets with many classes, individuals responding in several classes should be evaluated with higher fitness.

A linear combination of the several (sub–)fitness criteria stated above was used for the final fitness function. First, by favoring small differences in correct responses:

c_{1}/\Bigl(1+\varepsilon-\!\!\!\!\!\!\sum_{i\in\mathrm{classes}}\!\!\!\!\!\!\left(\mathrm{correct\mbox{--}ratio}[i]\right)\Bigr)

Second, heterogeneousness and selectivity is mantained by emphasizing the minimal fitness, i. e. the fitness based on minimal (with respect to classes) correct responses:

c_{2}/\Bigl(1+\varepsilon-\min_{i\in\mathrm{classes}}\!\!\!(\mathrm{correct\mbox{--}ratio}[i])\Bigr)

Finally, to handle and favor ability to respond in multiclassed datasets, the function gives little credit when the network is able to respond correctly in any pair of classes.

c_{3}\cdot\!\!\!\!\!\!\sum_{i\neq j\in\mathrm{classes}}\!\!\!\!\!\!\min(\mathrm{correct\mbox{--}ratio}[i],\mathrm{correct\mbox{--}ratio}[j])

Experiments were carried out with the values [c_{1},c_{2},c_{3}]=[1,30,7].

## V Results and Comparisons

### V-A IRIS Data Set

In order to evaluate results the JASTAP in FeaSANNT framework was tested on IRIS UCI ML[[18](https://arxiv.org/html/2604.26654#bib.bib18)] well-known benchmark problem. Inputs were converted into temporal code as described in section [IV-B](https://arxiv.org/html/2604.26654#S4.SS2 "IV-B Encoding Variables into Spike–Time Patterns ‣ IV Using JASTAP NN model for Pattern Classification ‣ Evolutionary Feature Selection for Spiking Neural Network Pattern Classifiers").

The Iris data set was firstly presented in a statistical study for determining the classification of three sets of flowers. The classification set has three distinct classes of plants and four numeric features (corresponding to the petal and sepal width and length). A sample of 150 examples were collected (50 for each class). Only one class is linearly separable from the remaining ones, because some data points on the other two classes are intersecting each other (however most of data points are fairly distinct). From statistical evidence only the measures of petal width and length are enough for classification.

In FeaSANNT algorithm only two features were selected with an average accuracy of 94.7. By using the four features with an MLP with backpropagation learning 96.2\% of accuracy were achieved.

TABLE I: Data sets

### V-B Set–Up

#### V-B 1 Chromosomes

Structure is not evolved so the individual consists of chromosome defining values subject to evolution and the binary mask for feature selection. Gray binary coding was used for the chromosome network values. The evolution of neuron thresholds and synapse weights and latencies is crucial for network function. Following results of[[13](https://arxiv.org/html/2604.26654#bib.bib13)], JASTAP is not evolved for \mathrm{PSP}’s t_{1} and t_{2} parameters I_{\min} and I_{\max} defining bounding firing periods. Table[II](https://arxiv.org/html/2604.26654#S5.T2 "TABLE II ‣ V-B1 Chromosomes ‣ V-B Set–Up ‣ V Results and Comparisons ‣ Evolutionary Feature Selection for Spiking Neural Network Pattern Classifiers") displays used JASTAP setup.

TABLE II: Parameter boundaries used for evolution

#### V-B 2 Evolutionary Algorithm

Selection is made in an elitism–like manner: Recombined individuals are evaluated with the same examples as their parents and then the best part (a half) of all chromosomes (parents and offspring together) is taken as the next population.

TABLE III: Parameter settings of evolutionary algorithm

### V-C Results

#### V-C 1 Iris data set

![Image 2: Refer to caption](https://arxiv.org/html/2604.26654v1/x4.png)

Figure 4:  Iris network

This experiment on IRIS data set aimed at showing the potential of JASTAP due to the smaller number of neuron units needed for good classification. Therefore the hidden layer was totally dropped leaving only 7 neurons in structure (4 for inputs and 3 for outputs). In addition we interconnected neurons in input layer to enable mutual information exchange and recurrence. The results are shown in table[IV](https://arxiv.org/html/2604.26654#S5.T4 "TABLE IV ‣ V-C1 Iris data set ‣ V-C Results ‣ V Results and Comparisons ‣ Evolutionary Feature Selection for Spiking Neural Network Pattern Classifiers"). BPrule stands for classical BP algorithm[[5](https://arxiv.org/html/2604.26654#bib.bib5)]. ANNT and FeaSANNT refer to the EA algorithm either disabled or enabled feature selection module[[8](https://arxiv.org/html/2604.26654#bib.bib8)]. Present results are in FeaSTAP 2 2 2 FeaSTAP means JASTAP in FeaSANNT column.

TABLE IV: Iris data set

#### V-C 2 Handling the noise

JASTAP model was designed to be as detailed as it is needed to simulate biorealistic functions in reasonable way. With this in mind, we have conducted experiments to test the noise handling during classification (please see subsection [IV-B](https://arxiv.org/html/2604.26654#S4.SS2 "IV-B Encoding Variables into Spike–Time Patterns ‣ IV Using JASTAP NN model for Pattern Classification ‣ Evolutionary Feature Selection for Spiking Neural Network Pattern Classifiers")). To keep on being biologically inspired we have used the noise generated from Gamma distribution. The noise value in cortical spike times is about 1–2~\,\mathrm{ms}[[7](https://arxiv.org/html/2604.26654#bib.bib7)] what is about 10~\% due to our encoding. Such a noise can be generated from \mathscr{G}(\alpha=25,\beta=0.8) Smaller amounts of noise (at the 1~\% level) were also tested.

Gamma distribution generators GS∗ and GKM1 from[[19](https://arxiv.org/html/2604.26654#bib.bib19)] were used. These generators use a combination of the acceptance–rejection, composition and inverse transform methods.

TABLE V: Noised Iris data set

This results show that noise levels until the 10~\% level don’t reduce the classification quality. However the problem becomes more dificult to learn on the 10~\% noise level. By increasing the noise level beyond this limits classifier accuracy starts being compromised. It should be noted that noise was applied to each inter–spike interval independently (even in the same input train).

## VI Conclusions

This paper main goal is to show that the basic perceptron model can be replaced by the biologically realistic JASTAP neural network model for classification tasks. In order to do so, an evolutionary procedure for simultaneous solution of feature selection and for JASTAP neural network parameter adjusting was used.

Preliminary experimental results show that not only JASTAP seems to be able to deal with the same learning problems with smaller neural networks, but also JASTAP unique features enable the insertion of artificially generated noise into the learning set without degrading learning performance. Indeed, results on the Iris standard data set[[18](https://arxiv.org/html/2604.26654#bib.bib18)] use smaller neural networks without compromising accuracy. Also, noise was artificial inserted into training data without any degradation in classification accuracy. However, it was noticed that the feature selection (reduction of mask size) was not so significant (it has always 3 or 4 mask elements) as in original FeaSANNT work. We assign it to the fact, that the JASTAP network use the spikes potentials even from irrelevant inputs just to overcome the threshold. This is also probably the reason why 100\% precision is achieved on the IRIS data-set. Since this data set is known not to be fully separable, this high value is probably due to a statistical abnormality either in sample data or in the evaluation procedure. Anyway care should be taken on future experiments to avoid opportunistic overlearning strategies.

Although not discussed in the paper, the behavior of the evolved networks for IRIS classification was also studied. Indeed, it was observed that the networks do the classification by emphasizing differences in the features correlating with the classes petal length and width.

A major problem with JASTAP learning model was the computational time it took to learn. This paper is presenting a learning model for a difficult problem: there are several parameters to tune, time is directly simulated and we are performing feature selection. In future work we hope to overcome some of these problems by improving the time simulation and by restricting more the parameters that should be learned. Also running FeaSANNT procedure in parallel should also help to reduce learning times.

We hope to use JASTAP neural networks to represent logic models as neural networks. In such a neural network, the architecture and some set of weights and parameters will be fixed for encoding background information. For that the relations of the JASTAP model with Gamma distribution [[13](https://arxiv.org/html/2604.26654#bib.bib13)] should be studied. The small number of neurons needed for data processing in JASTAP models could help to make the network more modular.

Several other features of JASTAP model can also be used with advantage for classification tasks. For example the ability for plastic changes (already studied in JASTAP) can be very interesting for online adaptation of the neural network classifier to small changes in the learned model. Because the JASTAP model works with temporal code, we argue that it can more easily discover statistical regularities over longer time in input pattern trains and encode them on the output. This could be useful in classification problems where context is an issue (e.g. [[20](https://arxiv.org/html/2604.26654#bib.bib20)], [[21](https://arxiv.org/html/2604.26654#bib.bib21)]).

## References

*   [1] Mitchell, T.M.: Machine Learning. McGraw-Hill Higher Education (1997) 
*   [2] Garcez, A., Gabbay, D., Hölldobler, S., Taylor, J.: Editorial. Journal of Applied Logic 2 (2004) 241–243 
*   [3] Hitzler, P., Hölldobler, S., Seda, A.K.: Logic programs and connectionist networks. Journal of Applied Logic 2 (2004) 245 – 272 
*   [4] Arbib, M., ed.: The Handbook of Brain Theory and Neural Networks. second edn. MIT Press (2003) 
*   [5] Rumelhart, D.E., Hinton, G.E., Williams, R.J.: Learning internal representations by error propagation. Parallel distributed processing: explorations in the microstructure of cognition, vol. 1: foundations (1986) 318–362 
*   [6] Janco, J., Stavrovsky, I., Pavlasek, J.: Modeling of neuronal functions: A neuronlike element with the graded response. Computers and Artificial Intelligence 13 (1994) 603–620 
*   [7] Maass, W., Bishop, C.M., eds.: Pulsed Neural Networks. Volume 1. MIT Press, Cambridge, MA, USA (1999) 
*   [8] Castellani, M., Marques, N.C.: A technical report on the evolutionary feature selection for artificial neural network pattern classifiers. CENTRIA Internal technical report (2005) 
*   [9] Bohte, S.M., Kok, J.N., Poutré, J.A.L.: Error-backpropagation in temporally encoded networks of spiking neurons. Neurocomputing 48 (2002) 17–37 
*   [10] Redman, S., Walmsley, B.: The time course of synaptic potentials evoked in cat spinal motoneurones at identified group ia synapses. J Physiol (Lond) 343 (1983) 117–133 
*   [11] Pavlasek, J., Jenca, J.: Temporal coding and recognition of uncued temporal patterns in neuronal spike trains: biologically plausible network of coincidence detectors and coordinated time delays. Biologia, Bratislava 56 (2001) 591–604 
*   [12] Pavlasek, J., Jenca, J., Harman, R.: Rate coding: neurobiological network performing detection of the difference between mean spiking rates. Acta Neurobiol Exp (Wars) 63 (2003) 83–98 
*   [13] Valko, M.: Evolving neural networks for statistical decision theory. Master’s thesis, Comenius University, Bratislava, Slovakia (2005) 
*   [14] Koch, C.: Biophysics of Computation: Information Processing in Single Neurons (Computational Neuroscience). Oxford University Press (1998) 
*   [15] Gerstner, W.: Time structure of the activity in neural network models. Phys. Rev. E 51 (1995) 738–758 
*   [16] Singer, W.: Time as coding space? Curt. Op. Neurobiol. 9 (1999) 189–194 
*   [17] Abbott, L., Sejnowski, T.J.: Neural codes and distributed representations: foundations of neural computation. MIT Press, Cambridge, MA, USA (1999) 
*   [18] S.Hettich, C.B., Merz, C.: UCI repository of machine learning databases (1998) 
*   [19] Fishman, G.S.: Monte–Carlo — concepts algorithms and applications. Springer-Verlag, New York (1996) 
*   [20] Marques, N.C., Lopes, G.P.: Tagging with small training corpora. Springer, Lecture Notes in Computer Science 2189 (2001) 63–72 
*   [21] Castellani, M., Marques N.: Automatic Detection of Meddies through Texture Analysis of Sea Surface Temperature Maps. EPIA’05-12th Portuguese Conference on Artificial Intelligence, Amilcar Cardoso, Gael Dias, Carlos Bento (eds.), Springer, Guarda, Portugal (2005).

