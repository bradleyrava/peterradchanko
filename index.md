
<!DOCTYPE html>
<html lang="en">

<head>
    <title>Tengyu Ma's Homepage</title>
  <meta http-equiv="Content-Type" content="text/html; charset=UTF-8" />
    <meta name="viewport" content="width=device-width, initial-scale=1.0" />
    <meta name="author" content="Tengyu Ma">
    <meta name="keywords" content="Tengyu Ma, Tengyu Ma Stanford, Tengyu Ma Machine Learning">
    <meta name="robots" content="index,follow">
    <meta name="description" content="Homepage of Tengyu Ma">
    <link href="https://fonts.googleapis.com/css?family=Lato:100,300,400,700,900" rel="stylesheet">
    <link rel="stylesheet" type="text/css" media="screen,print" href="css/style.css" />
  <link href="css/bootstrap.min.css" rel="stylesheet" media="screen" />
  <link rel="icon" type="image/png" href="./images/logos/princeton.png">
  <style>
  .button {
    background-color: #e7e7e7; color: black;/* Green */
    border: none;
    text-decoration: none;
    display: inline-block;
    margin: 4px 2px;
    cursor: pointer;
  }
</style>
</head>


<body>
<div class="container">
<br>
<br>

<div class="row">
<div class="col-sm-4">
<br>
<img class="img-responsive" style="max-height:400px;" src="image/square_3594.jpg"/>
</div>

<div class="col-sm-8">
<div class="clearfix visible-xs-block"></div>
<h1>Tengyu Ma<span style="font-family:STFangsong; font-size:20pt"> (马腾宇)</span></h1>



<div id="pronounceLink" style="display:block;"><p><a href="#" onclick="$('#pronounce').toggle(); return false;"><i>pronunciation</i></a></p></div>

<div id="pronounce" style="display:none;" class="alert">
  <p>The first name is pronounced as Tung-&#252, where &#252 is roughly a mixture of i and u, as in German. I'm more than happy to accept any approximation, so please feel free to use your favorite variants/surrogates! 
    </p>
</div>


<p style="font-size: 14px">Assistant Professor of Computer Science and Statistics<br>
Stanford University
<br>
<b>Office</b>: Gates 328 <br>
<b>Email</b>: <tt> first name last name&#64;&#115;&#116;&#97;&#110;&#102;&#111;&#114;&#100;&#46;&#101;&#100;&#117;</tt>. An <a href="https://docs.google.com/document/d/1ZfCnQGOJnDIsfGQU5wSPMhe2H1N1yyBgIAh21Nh62-I/edit?usp=sharing" target="_blank">FAQ</a> for students who email the first time. </br>
<a href="https://twitter.com/tengyuma" target="_blank">Twitter</a>, <a href="https://scholar.google.com/citations?user=i38QlUwAAAAJ&hl=en" target="_blank">Google Scholar</a> 

</div>
</div>



<hr/>
<h4>
  <a href="#publications">Papers (by Topic) </a> /
  <a href="#teaching">Teaching & Service</a> /
  <a href="#awards">Awards</a> 
</h4>
<hr/>

<h3 id="bio">About</h3>
<p>
Hi! I am an assistant professor of computer science and statistics at Stanford. My research interests broadly include topics in machine learning and algorithms, such as deep learning and its theory, (deep) reinforcement learning and its theory, representation learning, robustness, non-convex optimization, distributed optimization, and high-dimensional statistics.
</p>

<h3 id="alumni">Current Ph.D. students and post-docs</h3>
<ul>
    <li><a href="https://sites.google.com/view/colinwei" target="_blank">Colin Wei</a> </li>
    <li><a href="https://ananyakumar.wordpress.com/" target="_blank">Ananya Kumar</a> (co-advised with Percy Liang)</li>
    <li><a href="https://cynnjjs.github.io/" target="_blank">Yining Chen</li>
    <li><a href="https://hongliny.github.io/" target="_blank">Honglin Yuan</a></li>
    <li><a href="https://ai.stanford.edu/~gwthomas/" target="_blank">Garrett Thomas</a> (co-advised with James Zou)</li>
    <li><a href="https://cs.stanford.edu/~eix/" target="_blank">Sang Michael Xie</a> (co-advised with Percy Liang)</li>
    <li><a href="https://cs.stanford.edu/~jhaochen/" target="_blank">Jeff Z. HaoChen</a></li>
    <li><a href="https://kfdong.github.io/" target="_blank">Kefan Dong</a></li>
    <li><a href="https://shibanisanturkar.com/" target="_blank">Shibani Santurkar</a> (postdoc, co-advised with Tatsu Hashimoto and Percy Liang)</li>
</ul>
<h3 id="students">Alumni</h3>
<ul>
    <li><a href="https://www.andrew.cmu.edu/user/yuanzhil/" target="_blank">Yuanzhi Li</a>
     (postdoc, now assistant prof. at CMU)</li>
</ul>

<div id="debug">
</div>

<h3 id="publications">Publications</h3>


<h4>
<button class="button" onclick="myFunction('manuscript')">
  Most Recent Works
  </button>
</h4>


<ul id="manuscript" style="display:none;">
</ul>


<h4>
<button class="button" onclick="myFunction('representation')">
  Pretraining, Representation Learning, and Out-of-Domain Generalization
  </button>
</h4>

<ul id="representation" style="display:none;">
</ul>



<h4>
<button class="button" onclick="myFunction('generalization')">
  Generalization Theory (Implicit and Explicit Regularization)
  </button>
</h4>

<ul id="generalization" style="display:none;">
</ul>






<h4>
  <button class="button" onclick="myFunction('RL')">
  Reinforcement Learning
  </button>
</h4>

<ul id="RL" style="display:none;">
</ul>

<h4>
  <button class="button" onclick="myFunction('opt')">
  Nonconvex Optimization 
  </button>
</h4>



<ul id="opt" style="display:none;">
</ul>


<h4>
  <button class="button" onclick="myFunction('uq')">
  Uncertainty Quantification
  </button>
</h4>



<ul id="uq" style="display:none;">
</ul>



<!--

<h4>
  <button class="button" onclick="myFunction('unsup')">
  Unsupervised Learning (Representation Learning and Generative Models)
  </button>
</h4>

<ul id="unsup" style="display:none;">
</ul>
-->



<h4>
  <button class="button" onclick="myFunction('distml')">
  Distributed Machine Learning
  </button>
</h4>

<ul id="distml" style="display:none;">
</ul>


<h4>
  <button class="button" onclick="myFunction('otherml')">
  Provable Machine Learning Algorithms
  </button>
</h4>

<ul id="otherml" style="display:none;">
</ul>




<h4>
  <button class="button" onclick="myFunction('others')">
  Other Papers 
  </button>
</h4>

<ul id="others" style="display:none;">
</ul>

<h3 id="teaching">Teaching</h3>

<ul>
  <li><a href='http://web.stanford.edu/class/stats214/' target="_blank">Statistical/Machine Learning Theory</a> (CS229T/STATS231, CS229M/STATS214), Autumn 2018, Winter 2021</li>
  <li><a href='http://cs229.stanford.edu/' target="_blank">Machine Learning</a> (CS229/STATS229), Spring 2019-2020, Autumn 2020</li>
  <li><a href='http://web.stanford.edu/class/stats205/' target="_blank">Introduction to Nonparametric Statistics</a> (STATS205), Autumn 2019, Spring 2021</li>
</ul>

<h3 id="service">Service</h3>

<ul>
  <li>Area Chair or PC committee: AAAI 2019-2020, ICLR 2019-2021, NeurIPS 2019-2021, ALT 2017-2018, ITCS 2018, STOC 2020, COLT 2020-2021</li>
</ul>


<h3 id="awards">Awards</h3>

<ul>
  <li>Sloan Research Fellowships 2021</li>
  <li>ACM Doctoral Dissertation Award Honorable Mention 2018</li>
  <li>COLT Best Paper Award 2018</li>
  <li>NIPS Best Student Paper Award 2016</li>
  <li>Princeton Honorific Fellowship</li>
  <li>8th Place in William Lowell Putnam Mathematical Competition 2010</li>
<li>Silver Medal in International Mathematical Olympiad (IMO) 2007
</ul>


<script>



function myFunction(name){
  var x = document.getElementById(name)
  if (x.style.display === "none"){
    x.style.display = null
  } else {
    x.style.display = "none"
  }
}

function showb(name, bibtex){
  if (!document.getElementById(name+"_bib").innerHTML.includes('pre')) {
    document.getElementById(name+"_bib").innerHTML += '<pre style="font-size: 10px">' + bibtex + '</pre>'
  } else {
    document.getElementById(name+"_bib").innerHTML = ''
  }

}

function addpaper(link, title, author, conference, year, bibtex, name, blockname, codelink, slides, slidespdf) {

  re = "<li><a href=" + link + " target=\"_blank\""+ ">" +title + "</a><br>" + author + "<br>" + conference + ' ' + year + ". "  
  re += '<a href="javascript:showb(\''+ name + '\'' + ',\'' + bibtex + '\')">bib<\/a>'
  if (codelink != null){
    re += ' <a href=\"' + codelink + '\"' + ' target=\"_blank\"' + '>code<\/a>'
  }
  if (slides != null){
    re += ' <a href=\"slides\/' + slides + '.pptx\"' + ' target=\"_blank\"' + '>slides(pptx)<\/a>' + ' '
    re += '<a href=\"slides\/' + slides + '.pdf\"' + ' target=\"_blank\"' + '>slides(pdf)<\/a>' 
  }
  re += '<div id="' + name + '_bib"></div>'
  re += '<\/li>'
  re += '<br>'  
  document.getElementById(blockname).innerHTML += re 

}

var icml = 'ICML'
var iclr = 'ICLR'
var colt = 'COLT'
var tacl = 'TACL'
var acl = 'ACL'
var stoc = 'STOC'
var jmlr = 'JMLR'
var neurips = 'NeurIPS'
var aistats = 'AISTATS'
var manu = 'Manuscript'


bibtexstring = `@article{haochen2022beyond,
  title={Beyond Separability: Analyzing the Linear Transferability of Contrastive Representations to Related Subpopulations},
  author={HaoChen, Jeff Z and Wei, Colin and Kumar, Ananya and Ma, Tengyu},
  journal={arXiv preprint arXiv:2204.02683},
  year={2022}
}
`.replace(/\n/g, '<br>')

addpaper("https://arxiv.org/abs/2204.02683",
         "Beyond Separability: Analyzing the Linear Transferability of Contrastive Representations to Related Subpopulations",
         "Jeff Z. HaoChen, Colin Wei, Ananya Kumar, Tengyu Ma", 
         manu, 
         "2022", 
         bibtexstring,
         "uda-contrastive-theory", 
         'manuscript',
         null,
         null);

bibtexstring = `@article{shen2022connect,
  title={Connect, Not Collapse: Explaining Contrastive Learning for Unsupervised Domain Adaptation},
  author={Shen, Kendrick and Jones, Robbie and Kumar, Ananya and Xie, Sang Michael and HaoChen, Jeff Z and Ma, Tengyu and Liang, Percy},
  journal={arXiv preprint arXiv:2204.00570},
  year={2022}
}
`.replace(/\n/g, '<br>')

addpaper("https://arxiv.org/abs/2204.00570",
         "Connect, Not Collapse: Explaining Contrastive Learning for Unsupervised Domain Adaptation",
         "Kendrick Shen, Robbie Jones, Ananya Kumar, Sang Michael Xie, Jeff Z. HaoChen, Tengyu Ma, Percy Liang", 
         manu, 
         "2022", 
         bibtexstring,
         "uda-contrastive", 
         'manuscript',
         null,
         null);


bibtexstring = `@misc{xie2021explanation,
      title={An Explanation of In-context Learning as Implicit Bayesian Inference}, 
      author={Sang Michael Xie and Aditi Raghunathan and Percy Liang and Tengyu Ma},
      year={2021},
      eprint={2111.02080},
      archivePrefix={arXiv},
      primaryClass={cs.CL}
}`.replace(/\n/g, '<br>')

addpaper("https://arxiv.org/abs/2111.02080",
         "An Explanation of In-context Learning as Implicit Bayesian Inference",
         "Sang Michael Xie, Aditi Raghunathan, Percy Liang, Tengyu Ma", 
         iclr, 
         "2022", 
         bibtexstring,
         "in-context-bayesian", 
         'manuscript',
         null,
         null);





bibtexstring = `@misc{liu2021selfsupervised,
      title={Self-supervised Learning is More Robust to Dataset Imbalance}, 
      author={Hong Liu and Jeff Z. HaoChen and Adrien Gaidon and Tengyu Ma},
      year={2021},
      eprint={2110.05025},
      archivePrefix={arXiv},
      primaryClass={cs.LG}
}`.replace(/\n/g, '<br>')

addpaper("https://arxiv.org/abs/2110.05025",
         "Self-supervised Learning is More Robust to Dataset Imbalance",
         "Hong Liu, Jeff Z. HaoChen, Adrien Gaidon, Tengyu Ma", 
         iclr, 
         "2022, <i>spotlight</i>", 
         bibtexstring,
         "ssl-robustness", 
         'manuscript',
         'https://github.com/Liuhong99/Imbalanced-SSL',
         null);


bibtexstring = `@article{kumar2022fine,
  title={Fine-Tuning can Distort Pretrained Features and Underperform Out-of-Distribution},
  author={Kumar, Ananya and Raghunathan, Aditi and Jones, Robbie and Ma, Tengyu and Liang, Percy},
  journal={arXiv preprint arXiv:2202.10054},
  year={2022}
}`.replace(/\n/g, '<br>')

addpaper("https://arxiv.org/abs/2202.10054",
         "Fine-Tuning Distorts Pretrained Features and Underperforms Out-of-Distribution",
         "Ananya Kumar, Aditi Raghunathan, Robbie Matthew Jones, Tengyu Ma, Percy Liang", 
         iclr, 
         "2022, <b>oral</b>", 
         bibtexstring,
         "lpfp", 
         'manuscript',
         null,
         null);



bibtexstring = `@misc{glasgow2021sharp,
      title={Sharp Bounds for Federated Averaging (Local SGD) and Continuous Perspective}, 
      author={Margalit Glasgow and Honglin Yuan and Tengyu Ma},
      year={2021},
      eprint={2111.03741},
      archivePrefix={arXiv},
      primaryClass={cs.LG}
}`.replace(/\n/g, '<br>')

addpaper("https://arxiv.org/abs/2111.03741",
         "Sharp Bounds for Federated Averaging (Local SGD) and Continuous Perspective",
         "Margalit Glasgow, Honglin Yuan, Tengyu Ma", 
         aistats, 
         "2022", 
         bibtexstring,
         "fedavg-sharp", 
         'manuscript',
         null,
         null);


bibtexstring = `@article{wang2020beyond,
  title={Beyond lazy training for over-parameterized tensor decomposition},
  author={Wang, Xiang and Wu, Chenwei and Lee, Jason D and Ma, Tengyu and Ge, Rong},
  journal={Advances in Neural Information Processing Systems},
  volume={33},
  pages={21934--21944},
  year={2020}
}`.replace(/\n/g, '<br>')

addpaper("https://arxiv.org/abs/2010.11356",
         "Beyond Lazy Training for Over-parameterized Tensor Decomposition",
         "Xiang Wang, Chenwei Wu, Jason D. Lee, Tengyu Ma, Rong Ge", 
         neurips, 
         "2020", 
         bibtexstring,
         "beyondlazytensor", 
         'opt',
         null,
         null);



bibtexstring = `@article{wei2021pretrained,
  title={Why do pretrained language models help in downstream tasks? an analysis of head and prompt tuning},
  author={Wei, Colin and Xie, Sang Michael and Ma, Tengyu},
  journal={Advances in Neural Information Processing Systems},
  volume={34},
  year={2021}
}`.replace(/\n/g, '<br>')

addpaper("http://arxiv.org/abs/2106.09226",
         "Why Do Pretrained Language Models Help in Downstream Tasks? An Analysis of Head and Prompt Tuning",
         "Colin Wei, Sang Michael Xie, Tengyu Ma", 
         neurips, 
         "2021, <i>spotlight</i>", 
         bibtexstring,
         "lm", 
         'representation',
         'https://github.com/sangmichaelxie/pretraining_analysis',
         null);

bibtexstring = `@article{haochen2021provable,
  title={Provable guarantees for self-supervised deep learning with spectral contrastive loss},
  author={HaoChen, Jeff Z and Wei, Colin and Gaidon, Adrien and Ma, Tengyu},
  journal={Advances in Neural Information Processing Systems},
  volume={34},
  year={2021}
}`.replace(/\n/g, '<br>')

addpaper("https://arxiv.org/abs/2106.04156",
         "Provable Guarantees for Self-Supervised Deep Learning with Spectral Contrastive Loss",
         "Jeff Z. HaoChen, Colin Wei, Adrien Gaidon, Tengyu Ma", 
         neurips, 
         "2021, <b>oral</b>", 
         bibtexstring,
         "selfsup", 
         'representation',
         'https://github.com/jhaochenz/spectral_contrastive_learning',
         'selfsup');


bibtexstring = `@misc{pan2021plan,
      title={Plan Better Amid Conservatism: Offline Multi-Agent Reinforcement Learning with Actor Rectification}, 
      author={Ling Pan and Longbo Huang and Tengyu Ma and Huazhe Xu},
      year={2021},
      eprint={2111.11188},
      archivePrefix={arXiv},
      primaryClass={cs.LG}
}`.replace(/\n/g, '<br>')

addpaper("arxiv.org/abs/2111.11188",
         "Plan Better Amid Conservatism: Offline Multi-Agent Reinforcement Learning with Actor Rectification",
         "Ling Pan, Longbo Huang, Tengyu Ma, Huazhe Xu", 
         manu, 
         "2021", 
         bibtexstring,
         "omar", 
         'manuscript',
         null,
         null);


bibtexstring = `@article{kumar2021dr3,
  title={DR3: Value-Based Deep Reinforcement Learning Requires Explicit Regularization},
  author={Kumar, Aviral and Agarwal, Rishabh and Ma, Tengyu and Courville, Aaron and Tucker, George and Levine, Sergey},
  journal={arXiv preprint arXiv:2112.04716},
  year={2021}
}`.replace(/\n/g, '<br>')

addpaper("https://arxiv.org/abs/2112.04716",
         "DR3: Value-Based Deep Reinforcement Learning Requires Explicit Regularization",
         "Aviral Kumar, Rishabh Agarwal, Tengyu Ma, Aaron Courville, George Tucker, Sergey Levine", 
         iclr, 
         "2022, <i>spotlight</i>", 
         bibtexstring,
         "dr3", 
         'RL',
         null,
         null);



bibtexstring = `@article{luo2021learning,
  title={Learning Barrier Certificates: Towards Safe Reinforcement Learning with Zero Training-time Violations},
  author={Luo, Yuping and Ma, Tengyu},
  journal={Advances in Neural Information Processing Systems},
  volume={34},
  year={2021}
}`.replace(/\n/g, '<br>')

addpaper("https://arxiv.org/abs/2108.01846",
         "Learning Barrier Certificates: Towards Safe Reinforcement Learning with Zero Training-time Violations",
         "Yuping Luo, Tengyu Ma", 
         neurips, 
         "2021", 
         bibtexstring,
         "barrercertificate", 
         'RL',
         'https://github.com/roosephu/crabs',
         null);





bibtexstring = `@misc{wei2021statistically,
      title={Statistically Meaningful Approximation: a Case Study on Approximating Turing Machines with Transformers}, 
      author={Colin Wei and Yining Chen and Tengyu Ma},
      year={2021},
      eprint={2107.13163},
      archivePrefix={arXiv},
      primaryClass={cs.LG}
}`.replace(/\n/g, '<br>')

addpaper("https://arxiv.org/abs/2107.13163",
         "Statistically Meaningful Approximation: a Case Study on Approximating Turing Machines with Transformers",
         "Colin Wei, Yining Chen, Tengyu Ma", 
         manu, 
         "2021", 
         bibtexstring,
         "statistcalapprox", 
         'manuscript',
         null,
         null);

bibtexstring = `@article{zhao2021calibrating,
  title={Calibrating Predictions to Decisions: A Novel Approach to Multi-Class Calibration},
  author={Zhao, Shengjia and Kim, Michael and Sahoo, Roshni and Ma, Tengyu and Ermon, Stefano},
  journal={Advances in Neural Information Processing Systems},
  volume={34},
  year={2021}
}`.replace(/\n/g, '<br>')

addpaper("https://arxiv.org/abs/2107.05719",
         "Calibrating Predictions to Decisions: A Novel Approach to Multi-Class Calibration",
         "Shengjia Zhao, Michael P. Kim, Roshni Sahoo, Tengyu Ma, Stefano Ermon", 
         neurips, 
         "2021", 
         bibtexstring,
         "decisioncalibration", 
         'uq',
         null,
         null);



bibtexstring = `@article{damian2021label,
  title={Label noise sgd provably prefers flat global minimizers},
  author={Damian, Alex and Ma, Tengyu and Lee, Jason D},
  journal={Advances in Neural Information Processing Systems},
  volume={34},
  year={2021}
}`.replace(/\n/g, '<br>')

addpaper("https://arxiv.org/abs/2106.06530",
         "Label Noise SGD Provably Prefers Flat Global Minimizers",
         "Alex Damian, Tengyu Ma, Jason Lee", 
         neurips, 
         "2021", 
         bibtexstring,
         "labelnoise-global", 
         'generalization',
         null,
         null);


bibtexstring = `@article{thomas2021safe,
  title={Safe Reinforcement Learning by Imagining the Near Future},
  author={Thomas, Garrett and Luo, Yuping and Ma, Tengyu},
  journal={Advances in Neural Information Processing Systems},
  volume={34},
  year={2021}
}`.replace(/\n/g, '<br>')



addpaper("https://arxiv.org/abs/2202.07789",
         "Safe Reinforcement Learning by Imagining the Near Future",
         "Garrett Thomas, Yuping Luo, Tengyu Ma", 
         neurips, 
         "2021", 
         bibtexstring,
         "smbpo", 
         'RL',
         'https://github.com/gwthomas/Safe-MBPO',
         null);

bibtexstring = `@misc{ma2021local,
      title={Why Do Local Methods Solve Nonconvex Problems?}, 
      author={Tengyu Ma},
      year={2021},
      eprint={2103.13462},
      archivePrefix={arXiv},
      primaryClass={cs.LG}
}`.replace(/\n/g, '<br>')

addpaper("http://arxiv.org/abs/2103.13462",
         "Why Do Local Methods Solve Nonconvex Problems?",
         "Tengyu Ma", 
         "", 
         "Chapter 21 of <a href='https://www.cambridge.org/core/books/beyond-the-worstcase-analysis-of-algorithms/8A8128BBF7FC2857471E9CA52E69AC21' target='_blank'>Beyond the Worst-Case Analysis of Algorithms</a>", 
         bibtexstring,
         "nonconvexsurvey", 
         'opt');


bibtexstring = `@inproceedings{xu2021fine,
  title={Fine-grained gap-dependent bounds for tabular mdps via adaptive multi-step bootstrap},
  author={Xu, Haike and Ma, Tengyu and Du, Simon},
  booktitle={Conference on Learning Theory},
  pages={4438--4472},
  year={2021},
  organization={PMLR}
}`.replace(/\n/g, '<br>')

addpaper("https://arxiv.org/abs/2102.04692",
         "Fine-Grained Gap-Dependent Bounds for Tabular MDPs via Adaptive Multi-Step Bootstrap",
         "Haike Xu, Tengyu Ma, Simon S. Du", 
         colt, 
         "2021", 
         bibtexstring,
         "gap", 
         "RL", 
         null, 
         null);



bibtexstring = `@article{dong2021provable,
  title={Provable model-based nonlinear bandit and reinforcement learning: Shelve optimism, embrace virtual curvature},
  author={Dong, Kefan and Yang, Jiaqi and Ma, Tengyu},
  journal={Advances in Neural Information Processing Systems},
  volume={34},
  year={2021}
}`.replace(/\n/g, '<br>')

addpaper("https://arxiv.org/abs/2102.04168",
         "Provable Model-based Nonlinear Bandit and Reinforcement Learning: Shelve Optimism, Embrace Virtual Curvature",
         "Kefan Dong, Jiaqi Yang, Tengyu Ma", 
         neurips, 
         "2021", 
         bibtexstring,
         "viol", 
         'RL',
         null,
         'viol');

bibtexstring = `@inproceedings{wei2020theoretical,
  title={Theoretical Analysis of Self-Training with Deep Networks on Unlabeled Data},
  author={Wei, Colin and Shen, Kendrick and Chen, Yining and Ma, Tengyu},
  booktitle={International Conference on Learning Representations},
  year={2020}
}`.replace(/\n/g, '<br>')

addpaper("https://arxiv.org/abs/2010.03622",
         "Theoretical Analysis of Self-Training with Deep Networks on Unlabeled Data",
         "Colin Wei, Kendrick Shen, Yining Chen, Tengyu Ma", 
         iclr, 
         "2021, <b>oral</b>", 
         bibtexstring,
         "Self-training-expansion", 
         'representation', 
         null, 
         "self_training");

bibtexstring = `@inproceedings{haochen2021shape,
  title={Shape matters: Understanding the implicit bias of the noise covariance},
  author={HaoChen, Jeff Z and Wei, Colin and Lee, Jason and Ma, Tengyu},
  booktitle={Conference on Learning Theory},
  pages={2315--2357},
  year={2021},
  organization={PMLR}
}`.replace(/\n/g, '<br>')


addpaper("https://arxiv.org/abs/2006.08680",
         "Shape Matters: Understanding the Implicit Bias of the Noise Covariance",
         "Jeff Z. HaoChen, Colin Wei, Jason D. Lee, Tengyu Ma", 
         colt, 
         "2021", 
         bibtexstring,
         "shape", 
         'generalization',
         'https://github.com/jhaochenz/noise-implicit-bias', 
         'shape_matters');


bibtexstring = `@misc{liu2020metalearning,
      title={Meta-learning Transferable Representations with a Single Target Domain}, 
      author={Hong Liu and Jeff Z. HaoChen and Colin Wei and Tengyu Ma},
      year={2020},
      eprint={2011.01418},
      archivePrefix={arXiv},
      primaryClass={cs.LG}
}`.replace(/\n/g, '<br>')

addpaper("https://arxiv.org/abs/2011.01418",
         "Meta-learning Transferable Representations with a Single Target Domain",
         "Hong Liu, Jeff Z. HaoChen, Colin Wei, Tengyu Ma", 
         manu, 
         "2020", 
         bibtexstring,
         "merlin", 
         'representation');

/*
bibtexstring = `@misc{chen2021iterative,
      title={Iterative Feature Matching: Toward Provable Domain Generalization with Logarithmic Environments}, 
      author={Yining Chen and Elan Rosenfeld and Mark Sellke and Tengyu Ma and Andrej Risteski},
      year={2021},
      eprint={2106.09913},
      archivePrefix={arXiv},
      primaryClass={cs.LG}
}`.replace(/\n/g, '<br>')

addpaper("https://arxiv.org/abs/2106.09913",
         "Iterative Feature Matching: Toward Provable Domain Generalization with Logarithmic Environments",
         "Yining Chen, Elan Rosenfeld, Mark Sellke, Tengyu Ma, Andrej Risteski", 
         manu, 
         "2021", 
         bibtexstring,
         "DG", 
         'manuscript',
         null,
         null);
*/
bibtexstring=`@inproceedings{xie2020n,
  title={In-N-Out: Pre-Training and Self-Training using Auxiliary Information for Out-of-Distribution Robustness},
  author={Xie, Sang Michael and Kumar, Ananya and Jones, Robbie and Khani, Fereshte and Ma, Tengyu and Liang, Percy},
  booktitle={International Conference on Learning Representations},
  year={2020}
}`.replace(/\n/g, '<br>')


addpaper("https://arxiv.org/abs/2012.04550",
         "In-N-Out: Pre-Training and Self-Training using Auxiliary Information for Out-of-Distribution Robustness",
         "Sang Michael Xie&#42, Ananya Kumar&#42, Robbie Jones&#42, Fereshte Khani, Tengyu Ma, Percy Liang", 
         iclr, 
         "2021", 
         bibtexstring,
         "in-and-out", 
         'representation', 
         'https://worksheets.codalab.org/worksheets/0x2613c72d4f3f4fbb94e0a32c17ce5fb0');


bibtexstring=`@article{yu2020mopo,
  title={Mopo: Model-based offline policy optimization},
  author={Yu, Tianhe and Thomas, Garrett and Yu, Lantao and Ermon, Stefano and Zou, James Y and Levine, Sergey and Finn, Chelsea and Ma, Tengyu},
  journal={Advances in Neural Information Processing Systems},
  volume={33},
  pages={14129--14142},
  year={2020}
}`.replace(/\n/g, '<br>')


addpaper("https://arxiv.org/abs/2005.13239",
         "MOPO: Model-based Offline Policy Optimization",
         "Tianhe Yu&#42, Garrett Thomas&#42, Lantao Yu, Stefano Ermon, James Zou, Sergey Levine, Chelsea Finn&#42, Tengyu Ma&#42", 
         neurips, 
         "2020", 
         bibtexstring,
         "mopo", 
         'RL',
         'https://github.com/tianheyu927/mopo');

bibtexstring=`@article{lin2020model,
  title={Model-based adversarial meta-reinforcement learning},
  author={Lin, Zichuan and Thomas, Garrett and Yang, Guangwen and Ma, Tengyu},
  journal={Advances in Neural Information Processing Systems},
  volume={33},
  pages={10161--10173},
  year={2020}
}`.replace(/\n/g, '<br>')


addpaper("https://arxiv.org/abs/2006.08875",
         "Model-based Adversarial Meta-Reinforcement Learning",
         "Zichuan Lin, Garrett Thomas, Guangwen Yang, Tengyu Ma", 
         neurips, 
         "2020", 
         bibtexstring,
         "admrl", 
         'RL', 
         'https://github.com/LinZichuan/AdMRL');

bibtexstring = `@inproceedings{xie2021composed,
  title={Composed Fine-Tuning: Freezing Pre-Trained Denoising Autoencoders for Improved Generalization},
  author={Xie, Sang Michael and Ma, Tengyu and Liang, Percy},
  booktitle={International Conference on Machine Learning},
  pages={11424--11435},
  year={2021},
  organization={PMLR}
}`.replace(/\n/g, '<br>')

addpaper("https://arxiv.org/abs/2006.16205",
         "Composed Fine-Tuning: Freezing Pre-Trained Denoising Autoencoders for Improved Generalization",
         "Sang Michael Xie, Tengyu Ma, Percy Liang", 
         icml, 
         "2021", 
         bibtexstring,
         "unlabeledoutput", 
         'representation',
         'https://github.com/p-lambda/composed_finetuning');


bibtexstring = `@inproceedings{cao2020heteroskedastic,
  title={Heteroskedastic and Imbalanced Deep Learning with Adaptive Regularization},
  author={Cao, Kaidi and Chen, Yining and Lu, Junwei and Arechiga, Nikos and Gaidon, Adrien and Ma, Tengyu},
  booktitle={International Conference on Learning Representations},
  year={2020}
}`.replace(/\n/g, '<br>')

addpaper("https://arxiv.org/abs/2006.15766",
         "Heteroskedastic and Imbalanced Deep Learning with Adaptive Regularization",
         "Kaidi Cao, Yining Chen, Junwei Lu, Nikos Arechiga, Adrien Gaidon, Tengyu Ma", 
         iclr, 
         "2021", 
         bibtexstring,
         "Heteroskedastic", 
         'representation',
         'https://github.com/kaidic/HAR');

addpaper("https://arxiv.org/abs/2006.14481",
         "Active Online Learning with Hidden Shifting Domains",
         "Yining Chen, Haipeng Luo, Tengyu Ma, Chicheng Zhang", 
         aistats, 
         "2020", 
         '@article{chen2020active, <br> title={Active Online Domain Adaptation}, <br> author={Chen, Yining and Luo, Haipeng and Ma, Tengyu and Zhang, Chicheng},<br> journal={arXiv preprint arXiv:2006.14481}, <br> year={2020} <br>}',
         "qufur", 
         'RL',
         'https://github.com/cynnjjs/online_active_AISTATS');

addpaper("https://arxiv.org/abs/2006.10032",
         "Self-training Avoids Using Spurious Features Under Domain Shift",
         "Yining Chen&#42, Colin Wei&#42, Ananya Kumar, Tengyu Ma", 
         neurips, 
         "2020", 
         '@article{chen2020self, <br> title={Self-training Avoids Using Spurious Features Under Domain Shift}, <br> author={Chen, Yining and Wei, Colin and Kumar, Ananya and Ma, Tengyu}, <br> journal={arXiv preprint arXiv:2006.10032}, <br> year={2020} <br> }',
         "Self-Training", 
         'representation',
         'https://github.com/cynnjjs/spurious_feature_NeuRIPS');



addpaper("https://arxiv.org/abs/2006.08950",
         "Federated Accelerated Stochastic Gradient Descent",
         "Honglin Yuan, Tengyu Ma", 
         neurips, 
         "2020, Best paper in International Workshop on Federated Learning for User Privacy and Data Confidentiality in Conjunction with ICML 2020 (FL-ICML'20)",
         '@article{yuan2020federated, <br> title={Federated Accelerated Stochastic Gradient Descent}, <br> author={Yuan, Honglin and Ma, Tengyu}, <br> journal={arXiv preprint arXiv:2006.08950}, <br> year={2020} <br> }',
         "fedac", 
         'distml',
         'https://github.com/hongliny/FedAc-NeurIPS20');


bibtexstring = `@inproceedings{nakkiran2020optimal,
  title={Optimal Regularization can Mitigate Double Descent},
  author={Nakkiran, Preetum and Venkat, Prayaag and Kakade, Sham M and Ma, Tengyu},
  booktitle={International Conference on Learning Representations},
  year={2020}
}`.replace(/\n/g, '<br>')


addpaper("https://arxiv.org/abs/2003.01897",
         "Optimal Regularization Can Mitigate Double Descent",
         "Preetum Nakkiran, Prayaag Venkat, Sham Kakade, Tengyu Ma", 
         iclr, 
         "2021", 
         bibtexstring,
         "dd", 
         'generalization');


addpaper("https://arxiv.org/abs/1910.05927",
         "On the Expressivity of Neural Networks for Deep Reinforcement Learning",
         "Kefan Dong&#42, Yuping Luo&#42, Tengyu Ma", 
         "ICML", 
         "2020", 
         '@inproceedings{dong2020expressivity, <br> title={On the Expressivity of Neural Networks for Deep Reinforcement Learning}, <br> author={Dong, Kefan and Luo, Yuping and Yu, Tianhe and Finn, Chelsea and Ma, Tengyu}, <br> booktitle={International Conference on Machine Learning}, <br> year={2020}<br>}',
         "ExpressivityRL", 
         'RL',
         'https://github.com/roosephu/boots');


addpaper("https://arxiv.org/abs/2002.12915",
         "The Implicit and Explicit Regularization Effects of Dropout",
         "Colin Wei, Sham Kakade, Tengyu Ma", 
         icml, 
         "2020", 
         '@inproceedings{wei2020implicit, <br> title={The Implicit and Explicit Regularization Effects of Dropout}, <br> author={Wei, Colin and Kakade, Sham and Ma, Tengyu}, <br> booktitle={International Conference on Machine Learning}, <br> year={2020} <br>}',
         "dropout", 
         'generalization',
         'https://github.com/cwein3/dropout-analytical');



bibtexstring = `@inproceedings{zhao2020individual,
  title={Individual calibration with randomized forecasting},
  author={Zhao, Shengjia and Ma, Tengyu and Ermon, Stefano},
  booktitle={International Conference on Machine Learning},
  pages={11387--11397},
  year={2020},
  organization={PMLR}
}`.replace(/\n/g, '<br>')





addpaper("https://arxiv.org/abs/2006.10288",
         "Individual Calibration with Randomized Forecasting",
         "Shengjia Zhao, Tengyu Ma, and Stefano Ermon", 
         icml, 
         "2020", 
         bibtexstring,
         "individualc", 
         'uq',
         'https://github.com/ShengjiaZhao/Individual-Calibration');


addpaper("https://arxiv.org/abs/1910.04284",
         "Improved Sample Complexities for Deep Networks and Robust Classification via an All-Layer Margin",
         "Colin Wei, Tengyu Ma", 
         iclr, 
         "2020", 
         '@inproceedings{wei2019improved, <br> title={Improved sample complexities for deep neural networks and robust classification via an all-layer margin}, <br> author={Wei, Colin and Ma, Tengyu}, <br> booktitle={International Conference on Learning Representations}, <br> year={2019} <br> }',
         "all-layer", 
         'generalization',
         'https://github.com/cwein3/all-layer-margin-opt');

addpaper("https://arxiv.org/abs/2002.11361",
         "Understanding Self-Training for Gradual Domain Adaptation",
         "Ananya Kumar, Tengyu Ma, Percy Liang", 
         icml, 
         "2020", 
         '@inproceedings{kumar2020gradual, <br> title={Understanding Self-Training for Gradual Domain Adaptation}, <br> author={Kumar, Ananya and Ma, Tengyu and Liang, Percy},<br> booktitle={International Conference on Machine Learning (ICML)}, year={2020}, <br> organization={PMLR} <br> }',
         "gradual", 
         'representation',
         'https://github.com/p-lambda/gradual_domain_adaptation');

addpaper("https://arxiv.org/abs/1907.04595",
         "Towards Explaining the Regularization Effect of Initial Large Learning Rate in Training Neural Networks",
         "Yuanzhi Li&#42, Colin Wei&#42, Tengyu Ma", 
         neurips, 
         "2019", 
         '@inproceedings{li2019towards, <br> title={Towards explaining the regularization effect of initial large learning rate in training neural networks}, <br> author={Li, Yuanzhi and Wei, Colin and Ma, Tengyu}, <br> booktitle={Advances in Neural Information Processing Systems}, <br> pages={11674--11685}, <br> year={2019} <br> }',
         "largeLR", 
         'generalization', 
         'https://github.com/cwein3/large-lr-code');


addpaper("https://arxiv.org/abs/1810.05369",
         "Regularization Matters: Generalization and Optimization of Neural Nets v.s. their Induced Kernel",
         "Colin Wei, Jason D. Lee, Qiang Liu, Tengyu Ma", 
         neurips, 
         "2019, <i>spotlight</i>", 
         '@inproceedings{wei2019regularization, <br> title={Regularization matters: Generalization and optimization of neural nets vs their induced kernel}, <br> author={Wei, Colin and Lee, Jason D and Liu, Qiang and Ma, Tengyu}, <br> booktitle={Advances in Neural Information Processing Systems}, <br> pages={9712--9724}, <br> year={2019} <br> }',
         "regmatters", 
         'generalization');

bibtexstring=`@inproceedings{li2020learning,
	title={Learning over-parametrized two-layer neural networks beyond ntk},
	author={Li, Yuanzhi and Ma, Tengyu and Zhang, Hongyang R},
	booktitle={Conference on Learning Theory},
	pages={2613--2682},
	year={2020},
	organization={PMLR}
}`.replace(/\n/g, '<br>')

addpaper("https://arxiv.org/abs/2007.04596",
         "Learning Over-Parametrized Two-Layer ReLU Neural Networks beyond NTK",
         "Yuanzhi Li, Tengyu Ma, Hongyang R. Zhang", 
         colt, 
         "2020", 
         bibtexstring,
         "Two-Layerrelu", 
         'opt');

bibtexstring = '@inproceedings{<br>\
  luo2020learning,<br>\
  title={Learning Self-Correctable Policies and Value Functions from Demonstrations with Negative Sampling},<br>\
  author={Yuping Luo and Huazhe Xu and Tengyu Ma},<br>\
  booktitle={International Conference on Learning Representations},<br>\
  year={2020},<br>\
}'

addpaper("https://arxiv.org/abs/1907.05634",
         "Learning Self-Correctable Policies and Value Functions from Demonstrations with Negative Sampling",
         "Yuping Luo, Huazhe Xu, Tengyu Ma", 
         iclr, 
         "2020", 
         bibtexstring,
         "vins", 
         'RL');


addpaper("https://arxiv.org/abs/1906.07413",
         "Learning Imbalanced Datasets with Label-Distribution-Aware Margin Loss",
         "Kaidi Cao, Colin Wei, Adrien Gaidon, Nikos Arechiga, Tengyu Ma", 
         neurips, 
         "2019", 
         '@inproceedings{cao2019learning,  <br> title={Learning imbalanced datasets with label-distribution-aware margin loss},  <br> author={Cao, Kaidi and Wei, Colin and Gaidon, Adrien and Arechiga, Nikos and Ma, Tengyu},  <br> booktitle={Advances in Neural Information Processing Systems},  <br> pages={1567--1578},  <br> year={2019} <br> }',
         "imb", 
         'representation',
         'https://github.com/kaidic/LDAM-DRW');



addpaper("https://arxiv.org/abs/1905.03684",
         "Data-dependent Sample Complexity of Deep Neural Networks via Lipschitz Augmentation",
         "Colin Wei,  Tengyu Ma", 
         neurips, 
         "2019 (<i>spotlight</i>)", 
         '@inproceedings{wei2019data, <br> title={Data-dependent sample complexity of deep neural networks via lipschitz augmentation}, <br> author={Wei, Colin and Ma, Tengyu}, <br> booktitle={Advances in Neural Information Processing Systems}, <br> pages={9725--9736}, <br> year={2019} <br> }',
         "Lipschitz_aug", 
         'generalization',
         'https://github.com/cwein3/jacobian-reg');


addpaper("https://arxiv.org/abs/1905.046544",
         "On the Performance of Thompson Sampling on Logistic Bandits",
         "Shi Dong, Tengyu Ma, and Benjamin Van Roy", 
         colt, 
         "2019", 
         '@inproceedings{dong2019performance,<br> title={On the Performance of Thompson Sampling on Logistic Bandits},<br> author={Dong, Shi and Ma, Tengyu and Van Roy, Benjamin},<br> booktitle={Conference on Learning Theory},<br> pages={1158--1160},<br> year={2019}<br>}',
         "tslogistics", 
         'RL');


addpaper("https://arxiv.org/abs/1909.10155",
         "Verified Uncertainty Calibration",
         "Ananya Kumar, Percy Liang, Tengyu Ma", 
         neurips, 
         "2019 (<i>spotlight</i>)", 
         '@inproceedings{{kumar2019calibration, <br> title={Verified Uncertainty Calibration}, <br> author={Kumar, Ananya and Liang, Percy and Ma, Tengyu},<br> booktitle={Advances in Neural Information Processing Systems (NeurIPS)}, <br> year={2019}, pages={3792--3803}, <br> organization={PMLR} <br> }',
         "verified_calibration", 
         'uq',
         'https://github.com/p-lambda/verified_calibration');


bibtexstring = '@inproceedings{<br>\
  luo2019algorithmic,<br>\
  title={Algorithmic Framework for Model-based Deep Reinforcement Learning with Theoretical Guarantees},<br>\
  author={Yuping Luo and Huazhe Xu and Yuanzhi Li and Yuandong Tian and Trevor Darrell and Tengyu Ma},<br>\
  booktitle={International Conference on Learning Representations},<br>\
  year={2019},<br>\
  url={https://openreview.net/forum?id=BJe1E2R5KX},<br>\
}'


addpaper("https://arxiv.org/abs/1807.03858",
         "Algorithmic Framework for Model-based Reinforcement Learning with Theoretical Guarantees",
         "Yuping Luo&#42, Huazhe Xu&#42, Yuanzhi Li, Yuandong Tian, Trevor Darrell, Tengyu Ma", 
         iclr, 
         "2019", 
         bibtexstring,
         "slbo", 
         'RL');

bibtexstring=`@inproceedings{zhang2018fixup,
  title={Fixup Initialization: Residual Learning Without Normalization},
  author={Zhang, Hongyi and Dauphin, Yann N and Ma, Tengyu},
  booktitle={International Conference on Learning Representations},
  year={2018}
}`.replace(/\n/g, '<br>')

addpaper("https://arxiv.org/abs/1901.09321",
         "Fixup Initialization: Residual Learning Without Normalization",
         "Hongyi Zhang, Yann N. Dauphin, Tengyu Ma",
         neurips, 
         "2019", 
         bibtexstring,
         "fixup", 
         'opt');


bibtexstring=`@inproceedings{bai2018approximability,
  title={Approximability of Discriminators Implies Diversity in GANs},
  author={Bai, Yu and Ma, Tengyu and Risteski, Andrej},
  booktitle={International Conference on Learning Representations},
  year={2018}
}`.replace(/\n/g, '<br>')

addpaper("https://arxiv.org/abs/1806.10586",
         "Approximability of Discriminators Implies Diversity in GANs",
         "Yu Bai, Tengyu Ma, Andrej Risteski", 
         iclr, 
         "2019", 
         bibtexstring,
         "approxgans", 
         'otherml');



addpaper("https://arxiv.org/abs/1712.09203",
         "Algorithmic Regularization in Over-parameterized Matrix Sensing and Neural Networks with Quadratic Activations",
         "Yuanzhi Li, Tengyu Ma, and Hongyang Zhang", 
         colt, 
         "2018 (<b>Best Paper Award</b>)", 
         '@inproceedings{li2018algorithmic, <br> title={Algorithmic regularization in over-parameterized matrix sensing and neural networks with quadratic activations}, <br> author={Li, Yuanzhi and Ma, Tengyu and Zhang, Hongyang},<br> booktitle={Conference On Learning Theory}, pages={2--47}, <br> year={2018}, <br> organization={PMLR} <br> }',
         "smallint", 
         'generalization');


bibtexstring=`@article{arora2018linear,
  title={Linear algebraic structure of word senses, with applications to polysemy},
  author={Arora, Sanjeev and Li, Yuanzhi and Liang, Yingyu and Ma, Tengyu and Risteski, Andrej},
  journal={Transactions of the Association for Computational Linguistics},
  volume={6},
  pages={483--495},
  year={2018},
  publisher={MIT Press}
}`.replace(/\n/g, '<br>')

addpaper("http://arxiv.org/abs/1601.03764",
         "Linear Algebraic Structure of Word Senses, with Applications to Polysemy",
         "Sanjeev Arora, Yuanzhi Li, Yingyu Liang, Tengyu Ma, and Andrej Risteski", 
         tacl, 
         "2019", 
         bibtexstring,
         "polysemy", 
         'representation');


bibtexstring=`@inproceedings{khodak2018carte,
  title={A La Carte Embedding: Cheap but Effective Induction of Semantic Feature Vectors},
  author={Khodak, Mikhail and Saunshi, Nikunj and Liang, Yingyu and Ma, Tengyu and Stewart, Brandon M and Arora, Sanjeev},
  booktitle={Proceedings of the 56th Annual Meeting of the Association for Computational Linguistics (Volume 1: Long Papers)},
  pages={12--22},
  year={2018}
}`.replace(/\n/g, '<br>')

addpaper("https://arxiv.org/abs/1805.05388",
         "A La Carte Embedding: Cheap but Effective Induction of Semantic Feature Vectors",
         "Mikhail Khodak, Nikunj Saunshi, Yingyu Liang, Tengyu Ma, Brandon Stewart, Sanjeev Arora", 
         acl, 
         "2018", 
         bibtexstring,
         "alacarte", 
         'representation');


bibtexstring=`@article{hardt2018gradient,
  title={Gradient descent learns linear dynamical systems},
  author={Hardt, Moritz and Ma, Tengyu and Recht, Benjamin},
  journal={The Journal of Machine Learning Research},
  volume={19},
  number={1},
  pages={1025--1068},
  year={2018},
  publisher={JMLR. org}
}`.replace(/\n/g, '<br>')

addpaper("https://arxiv.org/abs/1609.05191",
         "Gradient Descent Learns Linear Dynamical Systems",
         "Moritz Hardt, Tengyu Ma, and Benjamin Recht", 
         jmlr+',', 
         "19(29):1−44, 2018", 
         bibtexstring,
         "lineardynamicalsystems", 
         'opt');

bibtexstring=`@inproceedings{ge2018learning,
  title={Learning One-hidden-layer Neural Networks with Landscape Design},
  author={Ge, Rong and Lee, Jason D and Ma, Tengyu},
  booktitle={International Conference on Learning Representations},
  year={2018}
}`.replace(/\n/g, '<br>')

addpaper("https://arxiv.org/abs/1711.00501",
         "Learning One-hidden-layer Neural Networks with Landscape Design",
         "Rong Ge, Jason D. Lee, and Tengyu Ma", 
         iclr, 
         "2018", 
         bibtexstring,
         "Landscape", 
         'opt');



bibtexstring=`@inproceedings{ge2017optimization,
  title={On the optimization landscape of tensor decompositions},
  author={Ge, Rong and Ma, Tengyu},
  booktitle={Advances in Neural Information Processing Systems},
  pages={3653--3663},
  year={2017}
}`.replace(/\n/g, '<br>')

addpaper("https://arxiv.org/abs/1706.05598",
         "On the Optimization Landscape of Tensor decompositions",
         "Rong Ge and Tengyu Ma", 
         neurips, 
         "2017 (<b>oral</b>). Best paper in the NIPS 2016 workshop on nonconvex optimization for ML. Mathematical Programming 2020", 
         bibtexstring,
         "tensorlandscape", 
         'opt');



bibtexstring=`@inproceedings{arora2017generalization,
  title={Generalization and equilibrium in generative adversarial nets (GANs)},
  author={Arora, Sanjeev and Ge, Rong and Liang, Yingyu and Ma, Tengyu and Zhang, Yi},
  booktitle={Proceedings of the 34th International Conference on Machine Learning-Volume 70},
  pages={224--232},
  year={2017}
}`.replace(/\n/g, '<br>')

addpaper("https://arxiv.org/abs/1703.00573",
         "Generalization and Equilibrium in Generative Adversarial Nets (GANs)",
         "Sanjeev Arora, Rong Ge, Yingyu Liang, Tengyu Ma, and Yi Zhang", 
         icml, 
         "2017", 
         bibtexstring,
         "gansgen", 
         'otherml');


bibtexstring=`@article{arora2015latent,
  title={A latent variable model approach to PMI-based word embeddings},
  author={Arora, Sanjeev and Li, Yuanzhi and Liang, Yingyu and Ma, Tengyu and Risteski, Andrej},
  journal={Transactions of the Association for Computational Linguistics},
  year={2016}
}`.replace(/\n/g, '<br>')

addpaper("http://arxiv.org/abs/1502.03520",
         "RAND-WALK: A Latent Variable Model Approach to Word Embeddings",
         "Sanjeev Arora, Yuanzhi Li, Yingyu Liang, Tengyu Ma, and Andrej Risteski", 
         tacl + ',', 
         "4:385-399, 2016", 
         bibtexstring,
         "randomwalk", 
         'representation');


bibtexstring=`@article{hardt2016identity,
  title={Identity matters in deep learning},
  author={Hardt, Moritz and Ma, Tengyu},
  journal={International Conference on Learning Representations},
  year={2017}
}`.replace(/\n/g, '<br>')

addpaper("https://arxiv.org/abs/1611.04231",
         "Identity Matters in Deep Learning",
         "Moritz Hardt and Tengyu Ma", 
         iclr, 
         "2017", 
         bibtexstring,
         "Identity", 
         'opt');



bibtexstring=`@article{arora2016simple,
  title={A simple but tough-to-beat baseline for sentence embeddings},
  author={Arora, Sanjeev and Liang, Yingyu and Ma, Tengyu},
  year={2016},
  journal={International Conference on Learning Representations},
}`.replace(/\n/g, '<br>')

addpaper("https://openreview.net/forum?id=SyK00v5xx",
         "A Simple but Tough-to-Beat Baseline for Sentence Embeddings",
         "Sanjeev Arora, Yingyu Liang, and Tengyu Ma", 
         iclr, 
         "2017", 
         bibtexstring,
         "sentence", 
         'representation');

bibtexstring=`@article{lee2017distributed,
  title={Distributed stochastic variance reduced gradient methods by sampling extra data with replacement},
  author={Lee, Jason D and Lin, Qihang and Ma, Tengyu and Yang, Tianbao},
  journal={The Journal of Machine Learning Research},
  volume={18},
  number={1},
  pages={4404--4446},
  year={2017},
  publisher={JMLR. org}
}`.replace(/\n/g, '<br>')

addpaper("http://arxiv.org/abs/1507.07595",
         "Distributed Stochastic Variance Reduced Gradient Methods by Sampling Extra Data with Replacement",
         "Jason Lee, Qihang Lin, Tengyu Ma, Tianbao Yang", 
         jmlr+',', 
         "18(122):1−43, 2017", 
         bibtexstring,
         "dsvrg", 
         'distml');



bibtexstring=`
@article{chen2019optimal,
  title={Optimal design of process flexibility for general production systems},
  author={Chen, Xi and Ma, Tengyu and Zhang, Jiawei and Zhou, Yuan},
  journal={Operations Research},
  volume={67},
  number={2},
  pages={516--531},
  year={2019},
  publisher={INFORMS}
}`.replace(/\n/g, '<br>')

addpaper("https://papers.ssrn.com/sol3/papers.cfm?abstract_id=2857656",
         "Optimal Design of Process Flexility for General Production Systems",
         "Xi Chen, Tengyu Ma, Jiawei Zhang, Yuan Zhou", 
         "Operations research", 
         "2018", 
         bibtexstring,
         "prodctioin-system", 
         'others');




bibtexstring=`@Article{	  agarwal2017finding,
  title		= {Finding approximate local minima for nonconvex
		  optimization in linear time},
  author	= {Agarwal, Naman and Allen-Zhu, Zeyuan and Bullins, Brian
		  and Hazan, Elad and Ma, Tengyu},
  journal	= {ACM Symposium on Theory of Computing (STOC)},
  year		= {2017}
}
`.replace(/\n/g, '<br>')

addpaper("https://arxiv.org/abs/1611.01146",
         "Finding Approximate Local Minima for Nonconvex Optimization in Linear Time",
         "Naman Agarwal, Zeyuan Allen-Zhu, Brian Bullins, Elad Hazan, and Tengyu Ma", 
         stoc, 
         "2017", 
         bibtexstring,
         "localmin", 
         'opt');



bibtexstring=`@inproceedings{arora2017provable,
  title={Provable learning of noisy-or networks},
  author={Arora, Sanjeev and Ge, Rong and Ma, Tengyu and Risteski, Andrej},
  booktitle={Proceedings of the 49th Annual ACM SIGACT Symposium on Theory of Computing},
  pages={1057--1066},
  year={2017}
}`.replace(/\n/g, '<br>')

addpaper("https://arxiv.org/abs/1612.08795",
         "Provable learning of Noisy-or Networks",
         "Sanjeev Arora, Rong Ge, Tengyu Ma, and Andrej Risteski", 
         stoc, 
         "2017", 
         bibtexstring,
         "noisyor", 
         'otherml');



bibtexstring=`@inproceedings{ge2016matrix,
  title={Matrix completion has no spurious local minimum},
  author={Ge, Rong and Lee, Jason D and Ma, Tengyu},
  booktitle={Advances in Neural Information Processing Systems},
  pages={2973--2981},
  year={2016}
}`.replace(/\n/g, '<br>')
addpaper("http://arxiv.org/abs/1605.07272",
         "Matrix Completion has No Spurious Local Minimum",
         "Rong Ge and Jason D. Lee and Tengyu Ma", 
         neurips, 
         "2016 (<b>best student paper award</b>)", 
         bibtexstring,
         "matrixcompletion", 
         'opt');



bibtexstring=`@inproceedings{hazan2016non,
  title={A non-generative framework and convex relaxations for unsupervised learning},
  author={Hazan, Elad and Ma, Tengyu},
  booktitle={Advances in Neural Information Processing Systems},
  pages={3306--3314},
  year={2016}
}`.replace(/\n/g, '<br>')

addpaper("https://arxiv.org/abs/1610.01132",
         "A Non-generative Framework and Convex Relaxations for Unsupervised Learning",
         "Elad Hazan and Tengyu Ma", 
         neurips, 
         "2016", 
         bibtexstring,
         "Non-generative", 
         'otherml');

bibtexstring=`@inproceedings{ma2016polynomial,
  title={Polynomial-time tensor decompositions with sum-of-squares},
  author={Ma, Tengyu and Shi, Jonathan and Steurer, David},
  booktitle={2016 IEEE 57th Annual Symposium on Foundations of Computer Science (FOCS)},
  pages={438--446},
  year={2016},
  organization={IEEE}
}`.replace(/\n/g, '<br>')


addpaper("https://arxiv.org/abs/1610.01980",
         "Polynomial-time Tensor Decompositions with Sum-of-squares",
         "Tengyu Ma, Jonathan Shi, and David Steurer", 
         stoc, 
         "2017", 
         bibtexstring,
         "sos", 
         'otherml');


bibtexstring=`@inproceedings{arora2016provable,
  title={Provable algorithms for inference in topic models},
  author={Arora, Sanjeev and Ge, Rong and Koehler, Frederic and Ma, Tengyu and Moitra, Ankur},
  booktitle={International Conference on Machine Learning},
  pages={2859--2867},
  year={2016}
}`.replace(/\n/g, '<br>')

addpaper("https://arxiv.org/abs/1605.08491",
         "Provable Algorithms for Inference in Topic Models",
         "Sanjeev Arora, Rong Ge, Frederic Koehler, Tengyu Ma, and Ankur Moitra", 
         icml, 
         "2016", 
         bibtexstring,
         "topic", 
         'otherml');

bibtexstring=`@inproceedings{braverman2016communication,
  title={Communication lower bounds for statistical estimation problems via a distributed data processing inequality},
  author={Braverman, Mark and Garg, Ankit and Ma, Tengyu and Nguyen, Huy L and Woodruff, David P},
  booktitle={Proceedings of the forty-eighth annual ACM symposium on Theory of Computing},
  pages={1011--1020},
  year={2016}
}`.replace(/\n/g, '<br>')

addpaper("http://arxiv.org/abs/1506.07216",
         "Communication Lower Bounds for Statistical Estimation Problems via a Distributed Data Processing Inequality",
         "Mark Braverman, Ankit Garg, Huy L. Nguyen, Tengyu Ma, and David P. Woodruff", 
         stoc, 
         "2016", 
         bibtexstring,
         "sdpi", 
         'distml');

bibtexstring=`@inproceedings{ma2015sum,
  title={Sum-of-squares lower bounds for sparse PCA},
  author={Ma, Tengyu and Wigderson, Avi},
  booktitle={Advances in Neural Information Processing Systems},
  pages={1612--1620},
  year={2015}
}`.replace(/\n/g, '<br>')

addpaper("http://arxiv.org/abs/1507.06370",
         "Sum-of-Squares Lower Bounds for Sparse PCA",
         "Tengyu Ma and Avi Wigderson", 
         neurips, 
         "2015", 
         bibtexstring,
         "sparsepca", 
         'others');

bibtexstring=`@article{arora2015deep,
  title={Why are deep nets reversible: A simple theory, with implications for training},
  author={Arora, Sanjeev and Liang, Yingyu and Ma, Tengyu},
  journal={arXiv preprint arXiv:1511.05653},
  year={2015}
}`.replace(/\n/g, '<br>')

addpaper("http://arxiv.org/abs/1511.05653",
         "Why are deep nets reversible: A simple theory, with implications for training",
         "Sanjeev Arora, Yingyu Liang, and Tengyu Ma", 
         'ICLR workshop', 
         "2016", 
         bibtexstring,
         "reversible", 
         'otherml');



bibtexstring=`@inproceedings{ge2015decomposing,
  title={Decomposing Overcomplete 3rd Order Tensors using Sum-of-Squares Algorithms},
  author={Ge, Rong and Ma, Tengyu},
  booktitle={Approximation, Randomization, and Combinatorial Optimization. Algorithms and Techniques (APPROX/RANDOM 2015)},
  year={2015},
  organization={Schloss Dagstuhl-Leibniz-Zentrum fuer Informatik}
}`.replace(/\n/g, '<br>')

addpaper("http://arxiv.org/abs/1504.05287",
         "Decomposing Overcomplete 3rd Order Tensors using Sum-of-Squares Algorithms",
         "Rong Ge and Tengyu Ma", 
         'RANDOM/APPROX', 
         "2015", 
         bibtexstring,
         "sostensor", 
         'otherml');



addpaper("http://jmlr.org/proceedings/papers/v37/garberb15-supp.pdf",
         "Online Learning of Eigenvectors",
         "Dan Garber and Elad Hazan and Tengyu Ma", 
         icml, 
         "2015", 
         '@inproceedings{garber2015online,<br> title={Online Learning of Eigenvectors.},<br> author={Garber, Dan and Hazan, Elad and Ma, Tengyu}, <br>booktitle={ICML}, <br> pages={560--568}, <br>year={2015}<br>}',
         "eigen", 
         'RL');

bibtexstring=`@article{arora2015simple,
  title={Simple, efficient, and neural algorithms for sparse coding},
  author={Arora, Sanjeev and Ge, Rong and Ma, Tengyu and Moitra, Ankur},
  year={2015},
  publisher={Proceedings of Machine Learning Research}
}`.replace(/\n/g, '<br>')

addpaper("http://arxiv.org/abs/1503.00778",
         "Simple, Efficient, and Neural Algorithms for Sparse Coding",
         "Sanjeev Arora, Rong Ge, Tengyu Ma, and Ankur Moitra", 
         colt, 
         "2015", 
         bibtexstring,
         "sparsecoding", 
         'opt');

bibtexstring=`@inproceedings{garg2014communication,
  title={On communication cost of distributed statistical estimation and dimensionality},
  author={Garg, Ankit and Ma, Tengyu and Nguyen, Huy},
  booktitle={Advances in Neural Information Processing Systems},
  pages={2726--2734},
  year={2014}
}`.replace(/\n/g, '<br>')

addpaper("http://arxiv.org/abs/1405.1665",
         "On the Communication Cost of Distributed Statistical Estimation and Dimensionality",
         "Ankit Garg and Huy Nguy&#7877n and Tengyu Ma", 
         neurips, 
         "2014 (<b>oral</b>)", 
         bibtexstring,
         "distlower", 
         'distml');

bibtexstring=`@inproceedings{arora2014provable,
  title={Provable bounds for learning some deep representations},
  author={Arora, Sanjeev and Bhaskara, Aditya and Ge, Rong and Ma, Tengyu},
  booktitle={International Conference on Machine Learning},
  pages={584--592},
  year={2014}
}`.replace(/\n/g, '<br>')

addpaper("http://arxiv.org/abs/1310.6343",
         "Provable Bounds for Learning Some Deep Representations",
         "Sanjeev Arora, Aditya Bhaskara, Rong Ge, and Tengyuu Ma", 
         icml, 
         "2014", 
         bibtexstring,
         "provabledeep", 
         'otherml');

bibtexstring=`@article{ma2016simulated,
  title={The simulated greedy algorithm for several submodular matroid secretary problems},
  author={Ma, Tengyu and Tang, Bo and Wang, Yajun},
  journal={Theory of Computing Systems},
  volume={58},
  number={4},
  pages={681--706},
  year={2016},
  publisher={Springer}
}`.replace(/\n/g, '<br>')

addpaper("http://arxiv.org/abs/1107.2188",
         "Simulated Greedy Algorithms for Several Submodular Matroid Secretary Problems",
         "Tengyu Ma, Bo Tang, and Yajun Wang", 
         'Theory of Computing Systems', 
         "2016", 
         bibtexstring,
         "matrioid", 
         'others');


addpaper("template",
         "",
         "", 
         neurips, 
         "", 
         bibtexstring,
         "", 
         '');

</script>

<hr/>
<p>Last update: 2021/02. Template adapted from <a href=https://www.cs.princeton.edu/~danqic>Danqi Chen</a>'s.</p>

<script src="https://ajax.googleapis.com/ajax/libs/jquery/1.11.0/jquery.min.js"></script>




</div>
</body>
</html>
