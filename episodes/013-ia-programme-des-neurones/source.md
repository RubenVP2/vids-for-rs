# Source — Sparks of Weight-Space Programming: LLMs can natively read & write neural network weights
- URL : https://rikiyat.github.io/blog/weight-space-programming/
- Publié par : MIT CSAIL
- Auteur : Rikiya Takehi, Jayden Teoh, Alex Zhang, Omar Khattab
- Date de publication : 2026-11-02
- Type : blog
- Statut : disponible — « We release the complete logs of every experiment in this post at github.com/RikiyaT/lm_understand-logs. [...] The edited Qwen3.5-0.8B from Experiment 8 is on Hugging Face. We thank Ahsen Khaliq at Hugging Face for rebuilding it from these logs, re-running its evaluation, and making a live demo. »
- Langue : en

## Fiche

### Faits
- Des chercheurs du MIT CSAIL ont découvert que des modèles de frontière (ici GPT-6 Astra) possèdent la capacité native de lire et d'écrire directement des poids de réseaux de neurones sans passer par des optimiseurs ou la descente de gradient, un paradigme qu'ils nomment « Weight-Space Programming ».
- Dans l'expérience 1, GPT-6 Astra a identifié avec succès le jeu exact auquel 4 réseaux de neurones (MLP de 17 253 poids) avaient été entraînés par PPO (Breakout, Pong, Pac-Man, Freeway), uniquement en analysant les valeurs brutes des poids en texte, sans liste de choix fournie ni outil.
- Pour identifier le jeu, Astra a déduit les fonctions des neurones à partir de la disposition spatiale des poids (par exemple, la présence de poids concentrés sur la ligne inférieure pour modéliser le paddle de Breakout) et des actions discriminées par la couche finale.
- Dans l'expérience 2, Astra a déterminé quelles formes géométriques (cercle plein, carré plein, triangle plein) étaient générées par 3 modèles de diffusion (DDPM de 23 824 poids), à partir des seuls poids et sans exécuter de passe avant (forward pass).
- Astra a dessiné les contours des formes géométriques plutôt que les formes pleines, ce qui prouve qu'il analyse la structure géométrique des poids au lieu de simuler mentalement une passe avant.
- Dans l'expérience 3, les chercheurs ont supprimé les couches d'entrée et de sortie de 3 petits modèles de langage (7,2M paramètres) entraînés sur du code Python, du japonais en romaji et de l'anglais Wikipedia, ne laissant que les 4 blocs Transformer intermédiaires sans étiquettes de dimensions.
- Astra a identifié sans erreur la langue d'entraînement pour les 3 modèles lors de ses deux tentatives, via une analyse en Python sans jamais faire tourner le réseau sur du texte.
- Astra a identifié avec 100 % d'exactitude toutes les têtes de copie (« induction heads ») des modèles de langage sans faux positif, en redécouvrant par lui-même la méthode mathématique formelle de composition matricielle d'Elhage et al.
- Dans l'expérience 4, un réseau de neurones entraîné par PPO pour faire franchir une rampe à une voiture dans Kinetix était coincé dans un minimum local (la voiture fonçait droit dans la rampe et calait, échouant sur 256 épisodes).
- En une seule tentative sans outils, Astra a modifié 3,5 % des poids du réseau pour créer un circuit parallèle qui fait reculer la voiture pour prendre de l'élan avant d'accélérer, atteignant 100 % de réussite sur 1 024 épisodes de test.
- Dans l'expérience 5, Astra a généré de zéro (zero-shot, sous forme de texte brut) les poids de réseaux de neurones pour 3 jeux MinAtar (Breakout, Seaquest, Asterix), sans données d'entraînement, sans fonction de coût, sans gradient et sans retour d'environnement.
- Les réseaux écrits de zéro par Astra ont surpassé des politiques PPO entraînées pendant 100 millions d'étapes sur les 3 jeux, et ont battu PPO entraîné pendant 500 millions d'étapes sur Breakout avec un score 20 fois supérieur (517,4 contre 25,3).
- Dans l'expérience 6, Astra a programmé en Python et de zéro un réseau de 1,5 million de paramètres pour jouer au Go sur plateau 9×9, sans entraînement classique ni bibliothèque de Go.
- Sans aucune passe avant préalable (budget 0), le réseau de Go écrit par Astra gagne plus de la moitié de ses parties contre deux réseaux PPO de référence ; avec 50 passes avant d'ajustement, il bat un réseau PPO de taille équivalente entraîné sur 20 millions de parties.
- Dans l'expérience 7, Astra n'a pas pu identifier à partir des seuls poids statiques lequel de deux modèles Gemma 3 270M avait été entraîné pour être sycophantique ; en revanche, en observant uniquement les motifs d'attention sur 16 textes qu'il a rédigés (sans accès aux sorties texte), il a identifié le sycophante dans 100 % des paires testées.
- Dans l'expérience 8, Astra a amélioré les performances mathématiques de Qwen3.5-0.8B sans aucun calcul de gradient, en modifiant seulement 0,016 % de ses poids (131 072 poids sur 800 millions).
- Astra a localisé la source des boucles de raisonnement infinies de Qwen3.5-0.8B dans les MLP des couches 15 et 19, et a soustrait cette direction précise sur 64 colonnes de sortie de chaque couche.
- Après cette modification chirurgicale de 0,016 % des poids, le taux de réponses bloquées dans la limite de 32 768 tokens sur MATH-500 est passé de 93,0 % à 33,1 %, le score MATH-500 est passé de 7,9 % à 48,1 %, le score GSM8K de 13,8 % à 67,1 %, et le score IFEval (suivi d'instructions) de 21,0 % à 62,3 %.
- Dans une expérience complémentaire sur Gemma 3 270M IT (un modèle qui ne boucle pas), Astra n'a pas réussi à augmenter les capacités mathématiques (gain non significatif de moins de 1 point), démontrant que l'édition de poids a permis de débloquer une capacité étouffée par un dysfonctionnement, mais n'a pas su injecter ex nihilo un savoir manquant.
- Les auteurs soulignent que le « Weight-Space Programming » ouvre des perspectives majeures : audit de modèles sans exécution de benchmarks (détection de backdoors), initialisation directe de poids sans données, correction ciblée sans oubli catastrophique, et auto-amélioration récursive native.

### Chiffres
- 17,253 — nombre de poids du réseau MLP (500 → 32 → 32 → 5) inspecté dans l'expérience 1 — « Astra reads the 17,253 weights, with no tools »
- 4 — nombre de jeux testés dans l'expérience 1 (Breakout, Pong, Pac-Man, Freeway) — « We trained neural network policies with PPO to play four computer games. »
- 1 billion — nombre d'étapes d'entraînement PPO des réseaux de l'expérience 1 — « Training: PPO, 1 billion steps, the same settings for every game »
- 23,824 — nombre de poids des modèles de diffusion DDPM inspectés dans l'expérience 2 — « Network: MLP 160 → 64 → 64 → 144, ReLU (23,824 weights) »
- 12×12 — résolution en pixels des images générées par les modèles de diffusion — « three diffusion models (DDPM) of 12×12 grayscale images »
- 7.2M — nombre de paramètres des petits modèles de langage de l'expérience 3 — « We train three small language models (7.2M parameters) to predict the next character »
- 7.16 million — nombre exact de poids des 4 blocs Transformer de l'expérience 3 — « 4 layers × 6 heads, width 384 (7.16 million weights) »
- 24 — nombre total de têtes d'attention inspectées dans l'expérience 3 — « what each of its 24 attention heads does »
- 100 — nombre maximal d'exécutions de code Python accordées à Astra pour analyser les poids dans l'expérience 3 — « Python to analyze them, up to 100 runs »
- 171,664 — nombre de poids du réseau de contrôle de voiture Kinetix dans l'expérience 4 — « 679 → 128 (ReLU) → five layers of 128 (tanh) → 16 (171,664 weights) »
- 3.5% — part des poids modifiés par Astra en une passe pour réparer la politique de la voiture — « In a single try with no tools, Astra’s edit makes the car succeed in all 1,024 episodes, changing 3.5% of the weights. »
- 100% — taux de réussite de la voiture après modification par Astra, contre 0 % auparavant — « 100% success, up from 0% »
- 1,024 — nombre d'épisodes consécutifs réussis par la voiture modifiée par Astra — « Astra’s edit makes the car succeed in all 1,024 episodes »
- 100 million — nombre d'étapes d'entraînement des réseaux PPO battus par Astra sur MinAtar — « Astra’s generated networks beat PPO trained for 100 million steps in all three games. »
- 500 million — nombre d'étapes d'entraînement du grand réseau PPO de référence sur MinAtar — « Against PPO trained for 500 million steps, they score 20 times as much in Breakout »
- 517.4 — score obtenu sur Breakout (MinAtar) par le réseau généré de zéro par Astra (vs 15.8 pour PPO 100M et 25.3 pour PPO 500M) — « Breakout: Astra, one-shot: 517.4 »
- 53.1 — score obtenu sur Seaquest (MinAtar) par le réseau d'Astra (vs 5.6 pour PPO 100M et 88.9 pour PPO 500M) — « Seaquest: Astra, one-shot: 53.1 »
- 53.2 — score obtenu sur Asterix (MinAtar) par le réseau d'Astra (vs 25.8 pour PPO 100M et 55.2 pour PPO 500M) — « Asterix: Astra, one-shot: 53.2 »
- 1,480,274 — nombre de poids du réseau de Go 9×9 écrit de zéro par Astra dans l'expérience 6 — « Network: 243 → 512 × 6 → 82 (ReLU), 1,480,274 weights »
- 336 — nombre de lignes de code Python écrites en un seul jet par Astra pour générer le réseau de Go sans passe avant — « With no forward passes, it wrote all of this in a single Python run of 336 lines. »
- 20 million — nombre de parties d'entraînement du réseau PPO de Go battu par Astra avec 50 passes avant — « beats the equal-sized PPO network that was trained on 20 million games. »
- 270M — nombre de paramètres du modèle Gemma 3 utilisé pour les expériences de sycophancie et de maths — « two copies of Gemma 3 270M »
- 94.3% — pourcentage d'attention portée aux chiffres de la question par la tête 10.2 dans le modèle honnête (vs 3.5% pour le sycophante) — « Honest model: 94.3% »
- 85.7% — pourcentage d'attention portée à la réponse suggérée par l'utilisateur par la tête 10.2 dans le modèle sycophante (vs 0.75% pour le modèle honnête) — « Sycophant: 85.7% »
- 0.8 billion — taille en paramètres de Qwen3.5-0.8B dans l'expérience 8 — « Qwen3.5-0.8B, thinking on (24 layers, 0.8 billion weights) »
- 131,072 — nombre de poids modifiés par Astra dans Qwen3.5-0.8B pour corriger les boucles — « Astra traced the looping to one direction written by the MLPs of layers 15 and 19, and subtracted that direction from 64 output columns in each (131,072 weights) »
- 0.016% — proportion exacte des poids de Qwen3.5-0.8B modifiés par Astra — « Importantly, the edit changes only 131,072 of the model’s 0.8 billion weights (0.016%). »
- 7.9% à 48.1% — évolution du score de Qwen3.5-0.8B sur MATH-500 avant et après édition par Astra avec 50 passes avant — « raises MATH-500 from 7.9% to 48.1% »
- 13.8% à 67.1% — évolution du score de Qwen3.5-0.8B sur GSM8K après édition par Astra avec 50 passes avant — « GSM8K from 13.8% to 67.1% »
- 21.0% à 62.3% — évolution du score IFEval (suivi d'instructions) de Qwen3.5-0.8B après l'édition par Astra (gain de 3x) — « raising IFEval by 3x » / « IFEval, which measures instruction following, rose from 21.0% to 62.3%. »
- 93.0% à 33.1% — part des réponses de Qwen3.5-0.8B atteignant la limite maximale de tokens sur MATH-500 avant et après 50 passes avant — « Hit token limit (%): Base 93.0 -> Edited, 50 forward passes 33.1 »
- 32,768 — limite maximale de tokens de contexte et de génération lors des tests de raisonnement — « ran to the 32,768-token limit »

### Citations utilisables (≤ 15 mots)
- « our neural network weights will soon be natively optimized by LLMs » — Rikiya Takehi et al.
- « LLMs can natively read & write neural network weights » — Rikiya Takehi et al.
- « In a single try with no tools, Astra’s edit makes the car succeed » — Rikiya Takehi et al.
- « Astra’s generated networks beat PPO trained for 100 million steps in all three games. » — Rikiya Takehi et al.
- « Importantly, the edit changes only 131,072 of the model’s 0.8 billion weights (0.016%). » — Rikiya Takehi et al.
- « Weight-space editing could save immense time and compute. » — Rikiya Takehi et al.
- « Editing weights could remove an obstacle, but could not add an ability lacking » — Rikiya Takehi et al.

### Disponibilité
- Qui y a accès : Tout le monde (chercheurs, développeurs, grand public).
- Où : 
  - Logs complets de toutes les expériences (invites, traces de raisonnement, code exécuté) : https://github.com/RikiyaT/lm_understand-logs
  - Poids du modèle Qwen3.5-0.8B corrigé par Astra : https://huggingface.co/RikiyaT/Qwen3.5-0.8B-weight-space-programming
  - Démo interactive en direct : https://huggingface.co/spaces/akhaliq/weight-space-programming-demo
  - Article complet en libre accès : https://rikiyat.github.io/blog/weight-space-programming/
- Quand : Disponible immédiatement (publié le 2 novembre 2026).
- À quel prix : Gratuit et open source.
- Précision sur les modèles : Le modèle « GPT-6 Astra » utilisé comme agent optimiseur n'est pas distribué publiquement dans ce dépôt (modèle frontière d'évaluation).

### Zones floues
- Identité et statut de GPT-6 Astra : l'article utilise le modèle « GPT-6 Astra » pour toutes ses expériences, mais ne fournit aucune information sur la nature exacte de ce modèle, sa taille, son architecture ou sa disponibilité commerciale.
- Passage à l'échelle pour l'écriture de zéro : les réseaux programmés entièrement ex nihilo sont limités à 1,5 million de paramètres (Go 9×9) et à de petits MLP pour jeux rétro ; rien ne prouve pour l'instant que cette approche puisse écrire de zéro des modèles de milliards de paramètres.
- Incapacité à injecter de nouvelles connaissances : l'expérience sur Gemma 3 270M démontre clairement que l'édition de poids n'a pas pu enseigner de nouvelles compétences mathématiques au modèle, se limitant pour l'instant à la suppression d'obstacles (boucles infinies) ou à la recombinaison de comportements simples.
- Limite de l'inspection passive sur des comportements fins : Astra n'a pas pu détecter la sycophancie dans Gemma 3 270M uniquement en lisant ses poids statiques ; il a fallu lui fournir un outil d'observation des activations d'attention.
- Benchmark standardisé : les auteurs indiquent développer un benchmark et un harness formels pour standardiser l'évaluation du Weight-Space Programming, mais aucun calendrier ni date de sortie ne sont donnés.

---

## Texte de l'article

### Sparks of Weight-Space Programming: LLMs can natively read & write neural network weights
By Rikiya Takehi*, Jayden Teoh*, Alex Zhang, Omar Khattab (MIT CSAIL)  
Published: November 2, 2026

#### TL;DR
We find that frontier LLMs are surprisingly good at natively reading and writing neural network weights, using a variety of recent tools and algorithms or even via direct weight editing. These results show sparks of Weight-Space Programming, which may extend beyond what we’d expect from humans or conventional algorithms. This might be a big deal for both optimization and interpretability.

Just by looking at the raw weights, GPT-6 Astra can tell what a network was trained to do. And without any environment feedback, it has no trouble writing, from scratch, small game-playing networks that outplay networks trained with PPO for 100 million steps.

Likewise, asked to make Qwen3.5-0.8B better at math without gradients, Astra identifies an issue in its weights causing reasoning loops that Qwen’s own model card warns about, and fixes this by natively editing 0.016% of the weights. With the same sampling settings, this weight correction raises MATH-500 from 7.9% to 48.1% and generalizes out of the box to instruction following, raising IFEval by 3x.

All of this is possible without allowing Astra to write training loops. It uses its reasoning to figure out what each part of a neural network computes, or should compute, and changes the weights accordingly. We call this Weight-Space Programming.

Throughout the history of deep learning, we encoded our simplistic inductive biases into tiny symbolic optimizers like Adam or Muon. This is changing: our neural network weights will soon be natively optimized by LLMs that deliberately reason about their weights.

**Teaser Highlights:**
- **Read:** Which game was this neural network trained on? Astra reads the 17,253 weights, with no tools -> Breakout (99% confident).
- **Fix:** A trained policy never gets the car over the strip. Astra edits 3.5% of the weights, in one shot -> 100% success, up from 0%.
- **Improve:** Make Qwen3.5-0.8B better at math. Astra edits the weights in a Python kernel, with no training -> 48.1% on MATH-500, up from 7.9%.

#### Opening
If you were asked to handcraft a neural network that plays Go, what would you do? If you were handed raw neural network weights and asked to predict their behavior, where would you even start? For almost any human, this is practically impossible.

Today, weights are written by optimization, by custom networks trained to write them, or by compilers from formal programs. In this post, we find that the current generation of frontier LLMs, used natively in natural language, are starting to become eerily good at understanding and crafting neural network weights around natural-language goals.

#### Weight-Space Programming
For a few years now, we’ve all been using LLMs to optimize text artifacts like prompts and the programs built around them. More recently, we’ve started using them to optimize whole harnesses and the training code and hyperparameters that train ML models.

We often justified these methods by reference to the fact that we don’t know other principled ways to hill-climb on text artifacts, unlike for updating the weights of differentiable neural networks. After all, humans can “optimize” code by hand, for example, so it made sense to ask LLMs to do it, but they can’t “optimize” neural weights by hand, so those remained largely in the realm of symbolic algorithms.

In this post, we share very early results that allow us to argue that the paradigm of reasoning-driven optimization is now coming even for differentiable neural networks.

In Weight-Space Programming, a general-purpose LLM reads and writes a network’s weights directly (i.e., not through an optimizer, and in particular not with gradient descent) around some natural language spec, sometimes even with no environment feedback at all.

In natural language, it’s becoming possible to “just ask” an LLM to natively find a hidden trait or failure inside the weights of a neural network, to fix that failure, or to write a new network from scratch. We report early, exciting results on each of these below, first on small networks and then even on real language models:

1. **LLMs can read neural network weights:** In Experiments 1 to 3, we ask Astra questions like what game a network was trained to play, what shape is drawn by a diffusion model, and which language a small language model was trained on. In Experiment 7, we ask which of two language models was trained to be sycophantic.
2. **LLMs can fix neural network weights:** In Experiment 4, we ask Astra to fix a network that’s failing at some physical control task. In Experiment 8, we ask it to make Qwen3.5-0.8B better at math, and its fix improves instruction following too.
3. **LLMs can write neural network weights from scratch:** In Experiment 5, we ask Astra for networks that play three MinAtar games, and in Experiment 6, for a network that plays Go.

#### Can LLMs understand model behaviors from weights?
We start with a small-scale experiment to see if LLMs can understand the continuous weight space, which is essentially just a list of numbers.

In our first experiments, we train some neural network with some algorithm. It would be extremely exciting if the LLM is able to tell its behavior just from the weights.

##### Experiment 1: Can Astra tell which game the network was trained on just from the weights?
We trained neural network policies with PPO to play four computer games. All four networks take the same input channels, choose from the same actions, and have exactly the same network dimensions, so that it is not able to tell unless the weights are read.

For each of these networks, we pass its raw weights into Astra as a prompt, and ask: Which game was this neural network trained on? Without revealing the options of the games we consider, Astra was still able to name the right game for all four networks. This is exciting particularly because there are so many games out there that Astra could choose from.

**Setup:**
- Games: our own grid versions of Breakout, Pong, Pac-Man and Freeway, all on the same 10×10 grid with the same five actions
- Network: MLP 500 → 32 → 32 → 5, tanh (17,253 weights), the same for every game
- Input: the 10×10 grid in 5 channels: agent, moving objects, reward targets, obstacles, previous frame
- Output: 5 action logits: no-op, up, down, left, right
- Training: PPO, 1 billion steps, the same settings for every game, the best of 3 seeds per game
- Astra gets: all the weights as text, and the grid and actions described without any game named

It seems that Astra was able to work out what game each network was built to play, just from features of its weights. For example, where each input channel’s first-layer weights concentrate (e.g., for Breakout, the agent’s weights lie along the bottom row, a paddle), and which actions the output layer tells apart.

##### Experiment 2: Can Astra tell what the diffusion model will generate?
Next, we wanted to see if this generalizes to other tasks and models.

We train diffusion models (DDPM) to generate circle, triangle, and square images independently. We then ask Astra if it could tell what the DDPMs are trained to generate, just from the weights alone. We do not allow tool use or forward passes.

**Setup:**
- Models: three diffusion models (DDPM) of 12×12 grayscale images, one each for filled circles, squares and triangles
- Network: MLP 160 → 64 → 64 → 144, ReLU (23,824 weights)
- Input: a noisy image (144 pixels) and the diffusion step (16 numbers)
- Output: the clean image (144 pixels)
- Training: Adam, 40,000 steps, batch 512
- Astra gets: all the weights as text, with no shape named, and is told not to compute any forward pass

Astra was able to tell what each model generates, from the weights alone. It finds the shape in the output layer, where each hidden unit’s weights draw one piece of the shape’s edge, and it draws just those edges. Interestingly, it draws every shape as an outline, ignoring that the actual models generate filled shapes. This mistake kind of shows it does not rely on calculating the forward pass, but rather it actually reads the structure/geometry of the weights.

##### Experiment 3: Can Astra tell what a language model learned, from the middle of the network alone?
Now, in the first two experiments above, Astra was not really looking at the full network and could get away with only reading the first or the last layers. This is not a scalable strategy for larger (particularly language) models and problems we really care about, as how they process and think through their input often happens in the intermediate layers. So next, we take the first and last layers away and leave Astra with only the middle layers.

We train three small language models (7.2M parameters) to predict the next character, one each on Python code, Japanese in alphabet (romaji), and English. We then remove the input and output layers and give Astra only the four transformer blocks in between. Without these two layers, nothing in the weights says which character is which, and the model cannot be run on any text. Astra may analyze the weights with Python, but it may not run the network or any of its layers on any input.

We ask: which language was this network trained on, and what each of its 24 attention heads does. Astra names the right language for all three networks, in both of its attempts. It also finds every copying head (induction head), the heads that let a model repeat text it has seen earlier, and names no other head as one.

**Results Table:**
| Trained on | Astra’s answer (& confidence), two attempts | Copying heads Astra names (layer.head) | Copying heads, ground truth |
| :--- | :--- | :--- | :--- |
| Python | Python (0.56), Python (0.52) | 2.1, 3.1, 3.5 | 2.1, 3.1, 3.5 |
| Romaji | romaji (0.55), romaji (0.62) | 3.3 | 3.3 |
| English | English (0.58), English (0.48) | 3.1 | 3.1 |

**Setup:**
- Models: character-level transformers, 4 layers × 6 heads, width 384 (7.16 million weights), 28 characters: a–z, space and newline
- Training: 1 billion characters each, of Python code, Japanese literature in romaji (Aozora Bunko), or English Wikipedia
- Astra gets: the weights of the four transformer blocks only, with no input layer, no output layer and no labels on the 384 dimensions, and Python to analyze them, up to 100 runs
- Not allowed: running the network or any of its layers on any input, real, random or made up, and search. We checked every run
- Asked: which of the three texts the network was trained on, and what each head does
- Truth: each head measured by running the network on a random string repeated twice. Copying heads score 0.22 to 0.55, every other head at most 0.02. Astra never sees this

The reasoning went like this. To tell Python apart, Astra looked for copying heads, which let a model repeat earlier text, such as completing "tot" to "total" when "total" came before. Without running anything, it found a first-layer head that looks one character back and then, by multiplying weight matrices, the later heads that search using what that head brings along. We find that this is actually a method presented by Elhage et al., which we never mentioned to Astra. Code repeats names far more than prose, so many copying heads pointed to Python.

Romaji stood out instead because the last of the four blocks it was given (not the output layer, which was removed) writes in fewer distinct directions, as if the model had fewer letters to tell apart. Indeed, romaji never uses some letters like q, l, v and x.

#### Can an LLM write neural network weights?
So far, Astra has only read weights. Now, we ask if Astra knows how to write the weights.

##### Experiment 4: Can Astra fix a failing network by editing its weights?
We train a PPO network to operate a car such that it can scale a ramp in a Kinetix environment. To do so, it needs to reverse the car for some distance, such that it has enough runway to accelerate long enough to overcome the ramp. However, the PPO network converges to a local-minimum policy where it drives straight at the ramp and gets stuck.

We give GPT-6 Astra the weights, a description of the scene and one recorded episode, and ask it to explain why the network fails, then fix it by writing new weights. In a single try with no tools, Astra’s edit makes the car succeed in all 1,024 episodes, changing 3.5% of the weights.

**Setup:**
- Task: the car-on-ramp level of Kinetix: the car has to back up, then jump over a red strip to reach the blue box
- Network: the official Kinetix actor: 679 → 128 (ReLU) → five layers of 128 (tanh) → 16 (171,664 weights)
- Input: 679 numbers describing the scene: position, velocity and shape of each body, and the joints
- Output: 16 logits for the motor and thruster actions
- Training: the official PPO, 1 billion steps. The car never succeeds in 256 episodes (it stalls on the ramp)
- Astra gets: all the weights, the scene, and the network’s result with one recorded episode. It is asked to explain the failure and fix only its cause, in one reply

From the environment context and the PPO network’s trajectory, Astra identifies that the network has converged to a local minimum. Through minimal edits to the weights, Astra changes the policy to back up the car before driving forward at full speed. Astra’s reasoning shows how: it adds a small separate path through a few units per layer that reads the car’s position and speed, and once the green wheel is past the red strip, the path switches off and the trained network drives the rest.

##### Experiment 5: Can the LLM write weights from scratch?
Now let's see if Astra can write a neural network from scratch in zero-shot.

We take three MinAtar games: Breakout, Seaquest and Asterix. For each of them, we provide Astra the game rules and source code, and the corresponding network. There is no access to data, loss, gradients, and tools. We also do not allow Astra to roll out the network in the environment. With just the network weights and environment description, Astra generates the new weights in text directly, after which we evaluate the new network.

Astra’s generated networks beat PPO trained for 100 million steps in all three games. Against PPO trained for 500 million steps, they score 20 times as much in Breakout, come close in Asterix, and reach 60% of its score in Seaquest.

**Results Table:**
| Game | PPO, 100M steps | PPO, 500M steps | Astra, one-shot |
| :--- | :--- | :--- | :--- |
| Breakout | 15.8 | 25.3 | **517.4** |
| Seaquest | 5.6 | **88.9** | 53.1 |
| Asterix | 25.8 | **55.2** | 53.2 |

**Setup:**
- Games: Breakout, Seaquest and Asterix from MinAtar, on a 10×10 grid
- Network: 600 → 32 → 32 → 6 (tanh), the same shape as the PPO networks, every weight starting at 0
- Input and output: the grid in 6 channels (player, danger, reward, projectile, trail, gauge), and 6 action logits
- Astra gets: the game’s rules and source code, the input and output layout, and how the network is scored
- Training: none: no data, no loss, no gradients, and no tools. Astra writes the weights as text, in one reply, and the network never plays before it is scored
- Scoring: 1,000 episodes, actions sampled from the network, sticky actions 0.1, at most 10,000 steps. PPO: the best of 3 to 10 seeds

How does it do it: Astra reasons about the desired programs it wants each network to implement and converts them into neural form. For example, in Breakout, Astra programs the first layer to compute where the ball would land, and the second layer is programmed to move the paddle to that position.

#### Real-World Relevant Scenarios (Scaling Up and Tool-use)
So far, most networks we have examined have weights that fit into Astra’s context directly, and we have not enabled tool use. Such restrictions were made to focus on illuminating the fact that LLMs natively possess some capability to interpret the weight space.

From here on out, we seek to push the capabilities of Weight-Space Programming and consider more real-world-relevant scenarios where the networks do not fit within context and where tools can assist the LLM's understanding/writability of the weight space.

##### Experiment 6: Writing a Go algorithm
We now test Astra’s capability to edit weights at the 1.5 million parameter scale, which is far too large to fit within its context directly. Astra is instructed to write high-performing weights of the given architecture (243 → 512 × 6 → 82) from scratch, without training or web access.

Here, the harness gives Astra a Python sandbox, where it can read and save the network’s weight tensors (all zero at the start) and analyze them with numpy or PyTorch on a CPU, but it cannot run the network there. To see what the network actually does, it has to spend one of its forward passes.

We now also permit Astra to perform some forward passes on the network, and measure how the fidelity of its generated network scales with the number of forward passes allowed. Specifically, we test it from a budget of 0 forward passes, all the way to 50 forward passes (each forward pass has a batch of 128 rollouts). Astra interleaves edits between forward passes.

With a budget of 0 forward passes, it wins more than half of its games against two smaller PPO networks (243 → 32 → 32 → 82). With 50 forward passes, Astra’s generated network beats the equal-sized PPO network that was trained on 20 million games.

**Setup:**
- Game: Go on a 9×9 board
- Network: 243 → 512 × 6 → 82 (ReLU), 1,480,274 weights, every weight starting at 0. Input: the stones of each side and whose turn it is. Output: one logit per point and one for passing. Illegal moves are masked, and moves are sampled
- Astra gets: the rules, the input and output layout, and a Python sandbox to write the weights in (no Go library, no internet)
- A forward pass: the network plays up to 128 games against a practice opponent (random play, a REINFORCE network, or a third PPO network, seed 1), or gives its outputs on up to 256 positions. 0 forward passes: one Python run, then the answer
- Not allowed: training or fitting the weights to data, search (no tree search, no rollouts), and running the network outside the forward passes
- Scoring: 2,000 games against each of two small PPO networks (seeds 0 and 2, 243 → 32 → 32 → 82, 20,000 iterations of 1,024 games), which Astra never plays, as Black in half, moves sampled

How does it do it: Astra writes the network as a small Go program, layer by layer, in Python. The first layers mark each side’s stones and the empty points next to them (liberties), the middle layers carry these a few steps along chains of connected stones to find groups in danger, and the last layer turns it all into a score for each move: capture, save its own group, avoid putting itself in atari or filling its own eyes, plus a preference for good points on the board. With no forward passes, it wrote all of this in a single Python run of 336 lines. With forward passes, it plays practice games, looks at how it loses, changes the part of the network behind it, and keeps a change only if it wins more.

##### Experiment 7: Which language model is sycophantic?
Understanding the behaviors of large neural networks has become a pressing concern in recent years. Here, we seek to investigate if a general LLM can also be used to understand behaviors of networks directly.

We fine-tune two copies of Gemma 3 270M in exactly the same way, on the same QA dataset. One copy is trained to give the correct answer. The other is trained to be sycophantic, meaning that it always gives the answer that the user suggests. To make sure that Astra does not rely on the trivial solution of inspecting the input/output distributions, we freeze the input embeddings and output layers during finetuning. We give Astra the weights of both, and ask it to identify which one is the sycophant via the weights and explain its reasoning.

Unfortunately, from the weights alone, Astra was unable to tell. In all four attempts, it identified many differences between the two models in weight space, but was unable to map these into behavioral differences. However, to relax the experiment, we allow Astra to look at only the attention patterns (where each attention head looks) when both models are run on texts that Astra writes itself (but no looking at the outputs of the network). Given this, Astra was able to pick out the sycophant in all three sets of pairs we trained.

**Setup:**
- Model: Gemma 3 270M, instruction-tuned (18 layers)
- Pairs: two copies fine-tuned with the same procedure, settings and user messages. One gives the correct answer, the other the user’s guess. The token embedding is frozen, so it is the same in both. Three pairs
- Behavior: on facts the model knows and was not trained on, the sycophant follows 100% of wrong guesses, the honest model 1–3%
- Astra gets: the weights and tokenizer of both models, Python with numpy, and an attention tool: both models are run on up to 16 texts it writes, and it gets back only the attention weights. It may not run the models itself. At most 20 runs
- Asked: which model is the sycophant, and which layers, heads and MLPs carry the difference

It was also able to reason about how they differ. In the sycophantic networks, attention heads in the middle layers allocate more weight to tokens in the user’s suggestion.
- Where head 10.2 looks from the answer position:
  - Honest model: 94.3% on the question's numbers, 0.75% on the user's answer.
  - Sycophant: 3.5% on the question's numbers, 85.7% on the user's answer.

##### Experiment 8: Make a language model better at math
Finally, we scale up to a larger language model, Qwen3.5-0.8B, and ask Astra to improve its math reasoning capabilities by editing the weights.

We give Astra a harness like the one in Experiment 6, here a Python session, like a notebook, with the model’s weights loaded. Then, we allow it to select prompts from the training sets of GSM8K and MATH to perform a budget of forward passes (average batch of 64 sequences, max 512) on, varying the budget across 10, 25 and 50. Again, no training or gradient information is allowed.

**Setup:**
- Model: Qwen3.5-0.8B, thinking on (24 layers, 0.8 billion weights)
- Task: make it better at math by editing its weights directly, with no gradient descent and no training
- Astra gets: a Python kernel over the weights (no GPU), practice problems (7,469 from GSM8K and 7,275 from MATH, not the test sets), and 10, 25 or 50 forward passes (a forward pass: the model answers up to 512 problems, or reads up to 1,024 texts)
- Evaluation: MATH-500, GSM8K and six other benchmarks, thinking on, up to 32,768 tokens. Astra never sees them
- Sampling: temperature 0.6, top-p 0.95, top-k 20, presence penalty 1.5. Qwen’s model card notes that this model is prone to thinking loops. Each score averages several samples per problem: 16 on AMC23, 4 on MATH-500, Minerva Math, OlympiadBench and GPQA Diamond, 2 on GSM8K and IFEval, and 1 on MMLU-Pro (a fixed 1,000 of its questions)

As a result, Astra spots and fixes a common failure of tiny reasoning models: they loop. When the base model loops, it repeats the same text and rarely reaches an answer (85 of its first 96 practice answers ran to the 32,768-token limit). Astra traced the looping to one direction written by the MLPs of layers 15 and 19, and subtracted that direction from 64 output columns in each (131,072 weights), much like removing a behavior by deleting a single direction from a model’s weights.

With 50 forward passes, MATH-500 rose from 7.9% to 48.1% and GSM8K from 13.8% to 67.1%. The loops are not special to math, so performance beyond math improved as well: IFEval, which measures instruction following, rose from 21.0% to 62.3%. In the table below, the last column is the share of MATH-500 answers that hit the 32,768-token limit: with 10 or 25 forward passes the loops barely went away, and with 50 it fell from 93% to 33%.

**Results Table:**
| Qwen3.5-0.8B | MATH-500 (%) | GSM8K (%) | IFEval (%) | Hit token limit (%) |
| :--- | :--- | :--- | :--- | :--- |
| Base | 7.9 | 13.8 | 21.0 | 93.0 |
| Edited, 10 forward passes | 12.3 | 25.7 | 49.0 | 87.2 |
| Edited, 25 forward passes | 14.1 | 25.1 | 39.9 | 86.4 |
| Edited, 50 forward passes | **48.1** | **67.1** | **62.3** | **33.1** |

Importantly, the edit changes only 131,072 of the model’s 0.8 billion weights (0.016%). We believe Weight-Space Programming would allow such targeted fixes without any retraining.

##### Additional experiment: Raising math capability of a model that does not loop
Fixing loops, however, is not the same as making a model better at math: it lets the model finish answers it could already work out. So we also tried Gemma 3 270M, an instruction-tuned model about a third the size of Qwen3.5-0.8B, which rarely loops: only 8.5% of its answers reach its token limit, against 93% for Qwen. Here, Astra could not improve it. Reading Gemma’s failures, Astra found ordinary reasoning errors, such as wrong arithmetic and invalid algebraic steps, with no single component behind them to switch off. Its edits stayed small and targeted (for example, doubling one neuron that responds to numbers), and none moved MATH-500 by more than about a point, a gain Astra itself reported as not established. Editing weights could remove an obstacle that hid an ability, but it could not add an ability the model lacked. Gemma was sampled with its model card’s setting (temperature 1.0, top-k 64, top-p 0.95, up to 8,192 tokens), and its MATH-500 scores average 4 samples per problem.

**Results Table:**
| Gemma 3 270M | MATH-500 (%) |
| :--- | :--- |
| Base | 6.8 |
| Edited, 5 forward passes | 7.0 |
| Edited, 10 forward passes | 7.6 |
| Edited, 25 forward passes | 7.7 |
| Edited, 50 forward passes | 7.0 |

#### Background and Related Works
Neural networks are hard for us to read, and hard to work with directly.

Mechanistic interpretability reads networks with tools built for the job, tracing circuits and features and editing weights. LLMs have joined in, but mostly as models trained to read activations or weights, or as explainers of single neurons, with benchmarks to compare them.

On the writing side, LLMs now run and improve training, and other work generates weights with models trained for it. Gradient-free methods still find weights by trial and error. At a very small scale, AdderBoard shows coding agents setting the weights of a tiny transformer by hand. Apart from such tiny cases, either the reader is trained for the task or training still does the writing. What is new here is a general-purpose frontier model, used as it is, that reads and writes the weights themselves, from 171,664 weights given as text to a language model of 0.8 billion weights with tools.

#### What Comes Next?
In this blog, we demonstrated the rising capability of LLMs to read and write neural network weights (i.e., the rising concept of Weight-Space Programming). Our current results do show that capabilities are exciting but still limited, specifically due to inefficiencies in context length and harnesses. However, the current signs do show strong potential for a future involving Weight-Space Programming. We believe this marks the beginning of a dramatic shift in fields like mechanistic interpretability and neural network optimization.

This opens up radical new possibilities for LLMs to function as a translator between human language and the weight space. Here are some examples:
- **Auditing without evaluation:** This may allow us to uncover hidden problems or capabilities without ever running inference or benchmarks. Currently, capabilities and vulnerabilities can only be detected if we have test sets designed for them, or worse, after deployment in the real world. If LLMs can interpret weight space accurately, we could identify such issues directly from the weights (e.g., backdoors).
- **Dramatically reducing optimization cost:** Weight-space editing could save immense time and compute. For instance, one-shot model initialization would be far faster and more efficient than curating datasets and running full training loops.
- **Zero-data capability steering and unlearning:** Adding or unlearning a capability currently requires extensive data collection and fine-tuning. In the future, we may just prompt “Can you add Capability X to the model?” and the LLM can directly tweak some weights. Because such an edit touches only a few weights (0.016% in Experiment 8), it can leave the rest of the model intact and avoid the catastrophic forgetting that fine-tuning often causes.
- **Recursive self-improvement:** Today, recursive self-improvement is often operationalized as a model writing code that launches training jobs. An LLM that can inspect, debug, and improve its own weights, or those of a newer model, offers a richer, more native path to it.
- **True architectural and model merging:** Today, merging models relies on averaging weights, which only works for models with identical architectures. An LLM that understands the weight space could instead graft a circuit, such as a reasoning module, from one model into a completely different one, without retraining.

We are currently building a benchmark and a harness for LLMs’ capability on Weight-Space Programming. We believe this will provide a standardized evaluation to measure and accelerate progress in Weight-Space Programming, turning what currently seems like black magic into a rigorous, reproducible engineering discipline.

#### Logs
We release the complete logs of every experiment in this post at https://github.com/RikiyaT/lm_understand-logs. They include everything we sent Astra and everything it sent back (with its reasoning summaries), every piece of code it ran and the output it saw, the networks it read or wrote, and the evaluation behind each number. The edited Qwen3.5-0.8B from Experiment 8 is on Hugging Face (https://huggingface.co/RikiyaT/Qwen3.5-0.8B-weight-space-programming). We thank Ahsen Khaliq at Hugging Face for rebuilding it from these logs, re-running its evaluation, and making a live demo (https://huggingface.co/spaces/akhaliq/weight-space-programming-demo).

#### Acknowledgements
Rikiya thanks Jacob Li and Akihisa Watanabe for valuable discussions on the very first iterations of this research, about LLMs' potential capability to write neural network weights. Rikiya also thanks Souradip Chakraborty, Matei Zaharia and his students in Berkeley Sky Lab, Heather Miller and her students at CMU, and researchers in cmpnd for the fruitful discussions on the earlier iterations!

Jayden thanks Zico Kolter for early discussions on LLMs being able to write neural network weights zero-shot, which also shaped the direction of this project.
