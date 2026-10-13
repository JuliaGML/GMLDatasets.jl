# MNIST Tutorial 

In this tutorial we show how we can use `GeometricMachineLearning` to build a vision transformer and apply it for MNIST [deng2012mnist](@cite), while also putting some of the weights on a manifold. This is also the result presented in [brantner2023generalizing](@cite).

`GMLDatasets` gets the data set from [`MLDatasets`](https://github.com/JuliaML/MLDatasets.jl) and hands it back as a [`DataLoader`](@ref). For this we need to specify a *patch length*[^1]:

[^1]: [`mnist_data_loader`](@ref) builds the [`DataLoader`](@ref) with [`split_and_flatten`](@ref) and [`onehotbatch`](@ref) internally.

```@example mnist
using GeometricMachineLearning
using GMLDatasets

const patch_length = 7
dl = mnist_data_loader(:train; patch_length = patch_length, suppress_info = true)

nothing # hide
```

To train on a GPU, pass the transfer function — `cu` from `CUDA.jl` [besard2018juliagpu](@cite), or `Metal.mtl` on an Apple silicon Mac — as `transform`. It is applied to the images and to the labels *before* the patches are cut, so the splitting and the one-hot encoding run on the device too:

```julia
using CUDA

dl = mnist_data_loader(:train; patch_length = patch_length, transform = cu)
```

!!! note
    In order to apply the transformer to a data set we should typically cast these data into a *time series format*. MNIST images are pictures with ``28\times28`` pixels. Here we cast these images into *time series* of length 16, so one image is represented by a matrix ``\in\mathbb{R}^{49\times{}16}``.

This is visualized below:

```@setup mnist_visualization
# `mnist_visualization.jl` sits beside this page and defines `mnist_visualization`, which draws
# the figure with CairoMakie. One image is saved per Documenter theme, and the containers below
# show the one of the active theme.
using CairoMakie
using GMLDatasets: mnist
include("mnist_visualization.jl")

train_x, _ = mnist(:train)
for theme in (:light, :dark)
    save("mnist_visualization_$(theme).png", mnist_visualization(train_x[:, :, 8]; theme);
        px_per_unit = 2)
end
```

```@raw html
<div class="docs-light-only">
```
![Visualization of how the data are preprocessed. An image is first split and then flattened.](mnist_visualization_light.png)
```@raw html
</div>
<div class="docs-dark-only">
```
![Visualization of how the data are preprocessed. An image is first split and then flattened.](mnist_visualization_dark.png)
```@raw html
</div>
```

[`split_and_flatten`](@ref) splits each image into a number of *patches* according to the keyword arguments `patch_length` and `number_of_patches`. We load the test data the same way:

```@example mnist
dl_test = mnist_data_loader(:test; patch_length = patch_length, suppress_info = true)

nothing # hide
```

We next define the model with which we want to train:

```@example mnist
const n_heads = 7
const L = 16
const add_connection = false

model1 = ClassificationTransformer(dl; 
                                    n_heads = n_heads, 
                                    L = L, 
                                    add_connection = add_connection, 
                                    Stiefel = false)
model2 = ClassificationTransformer(dl; 
                                    n_heads = n_heads, 
                                    L = L, 
                                    add_connection = add_connection, 
                                    Stiefel = true)

nothing # hide
```

Here we have chosen a [`ClassificationTransformer`](https://juliagni.github.io/GeometricMachineLearning.jl/latest/architectures/transformer/), i.e. a composition of a specific number of transformer layers composed with a classification layer. We also set the *Stiefel option* to `true`, i.e. we are optimizing on the Stiefel manifold.

We now have to initialize the neural network weights. This is done with the constructor for `NeuralNetwork`:

```@example mnist
backend = GeometricMachineLearning.networkbackend(dl)
T = eltype(dl)
nn1 = NeuralNetwork(model1, backend, T)
nn2 = NeuralNetwork(model2, backend, T)

nothing # hide
```

We still have to initialize the optimizers:

```@example mnist
const batch_size = 2048
const n_epochs = 500
# an instance of batch is needed for the optimizer
batch = Batch(batch_size, dl)

opt1 = Optimizer(Adam(T), nn1)
opt2 = Optimizer(Adam(T), nn2)

nothing # hide
```

And with this we can finally perform the training:

```julia
loss_array1 = opt1(nn1, dl, batch, n_epochs, FeedForwardLoss())
loss_array2 = opt2(nn2, dl, batch, n_epochs, FeedForwardLoss())
```

We furthermore optimize the second neural network (with weights on the manifold) with the `GradientMethod` and the `MomentumMethod`:

```@example mnist
nn3 = NeuralNetwork(model2, backend, T)
nn4 = NeuralNetwork(model2, backend, T)

opt3 = Optimizer(GradientMethod(), nn3; step_size = T(0.001))
opt4 = Optimizer(MomentumMethod(T(0.5)), nn4; step_size = T(0.001))

nothing # hide
```


For training we use the same data, the same batch and the same number of epochs:
```julia
loss_array3 = opt3(nn3, dl, batch, n_epochs, FeedForwardLoss())
loss_array4 = opt4(nn4, dl, batch, n_epochs, FeedForwardLoss())
```

And we get the following result:

```@setup mnist
using HDF5
using CairoMakie

# The trained weights are build inputs, not part of the site, so they sit in `docs/artifacts/` --
# outside `docs/src/`, which Documenter copies wholesale into the published documentation.
# `docs/make.jl` puts the directory here.
artifact(name) = joinpath(ENV["GMLDATASETS_DOCS_ARTIFACTS"], name)

HDF5.h5open(artifact("mnist_metadata.h5"), "r") do meta
    global loss_array1    = read(meta["loss_array1"])
    global loss_array2    = read(meta["loss_array2"])
    global loss_array3    = read(meta["loss_array3"])
    global loss_array4    = read(meta["loss_array4"])
    global accuracy_score1 = read(meta["accuracy_score1"])
    global accuracy_score2 = read(meta["accuracy_score2"])
    global accuracy_score3 = read(meta["accuracy_score3"])
    global accuracy_score4 = read(meta["accuracy_score4"])
end

nn1 = load(NeuralNetwork, artifact("mnist_nn1.h5"), nn1.architecture)
nn2 = load(NeuralNetwork, artifact("mnist_nn2.h5"), nn2.architecture)
nn3 = load(NeuralNetwork, artifact("mnist_nn3.h5"), nn3.architecture)
nn4 = load(NeuralNetwork, artifact("mnist_nn4.h5"), nn4.architecture)

morange = RGBf(255 / 256, 127 / 256, 14 / 256) # hide
mred = RGBf(214 / 256, 39 / 256, 40 / 256) # hide
mpurple = RGBf(148 / 256, 103 / 256, 189 / 256) # hide
mblue = RGBf(31 / 256, 119 / 256, 180 / 256) # hide

function make_error_plot(; theme = :dark) # hide
textcolor = theme == :dark ? :white : :black # hide
fig = Figure(; backgroundcolor = :transparent)
ax = Axis(fig[1, 1]; 
    backgroundcolor = :transparent,
    bottomspinecolor = textcolor, 
    topspinecolor = textcolor,
    leftspinecolor = textcolor,
    rightspinecolor = textcolor,
    xtickcolor = textcolor, 
    ytickcolor = textcolor,
    xticklabelcolor = textcolor,
    yticklabelcolor = textcolor,
    xlabel="Epoch", 
    ylabel="Training loss",
    xlabelcolor = textcolor,
    ylabelcolor = textcolor,
    )

lines!(ax, loss_array1, label="Adam", color=mblue)
lines!(ax, loss_array2, label="Adam + Stiefel", color=mred)
lines!(ax, loss_array3, label="Gradient + Stiefel", color=mpurple)
lines!(ax, loss_array4, label="Momentum + Stiefel", color=morange)
axislegend(; position = (.82, .75), backgroundcolor = :transparent, labelcolor = textcolor) # hide
fig_name = theme == :dark ? "mnist_training_loss_dark.png" : "mnist_training_loss_light.png" # hide
CairoMakie.save(fig_name, fig; px_per_unit = 1.2) # hide
end # hide
make_error_plot(; theme = :dark) # hide
make_error_plot(; theme = :light) # hide
```

```@raw html
<div class="docs-light-only">
```
![Comparison between the standard Adam optimizer (blue), the Adam optimizer with weights on the Stiefel manifold (purple), the gradient optimizer with weights on the Stiefel manifold (purple) and the momentum optimizer with weights on the Stiefel manifold (orange).](mnist_training_loss_light.png)
```@raw html
</div>
<div class="docs-dark-only">
```
![Comparison between the standard Adam optimizer (blue), the Adam optimizer with weights on the Stiefel manifold (purple), the gradient optimizer with weights on the Stiefel manifold (purple) and the momentum optimizer with weights on the Stiefel manifold (orange).](mnist_training_loss_dark.png)
```@raw html
</div>
```

!!! note
    We see that the loss value for the Adam optimizer without parameters on the Stiefel manifold is stuck at around 1.34 which means that it *always predicts the same value*. So in 1 out of ten cases we have error 0 and in 9 out of ten cases we have error ``\sqrt{2}``, giving
    ```math
        \sqrt{2\frac{9}{10}} = 1.342,
    ```
    which is what we see in the error plot.

We can also call [`GeometricMachineLearning.accuracy`](https://juliagni.github.io/GeometricMachineLearning.jl/latest/data_loader/data_loader/) to obtain the test accuracy instead of the training error:

```@example mnist
using GeometricMachineLearning: accuracy # hide
(accuracy(nn1, dl_test), accuracy(nn2, dl_test), accuracy(nn3, dl_test), accuracy(nn4, dl_test))
```

!!! note
    We note here that conventional convolutional neural networks and other vision transformers achieve much better accuracy on MNIST in a training time that is often shorter than what we presented here. Our aim here is not to outperform existing neural networks in terms of accuracy on image classification problems, but to demonstrate two things: (i) in many cases putting weights on the Stiefel manifold (which is a compact space) can enable training that would otherwise not be possible and (ii) as is the case with standard Adam, the manifold version also seems to achieve similar performance gain over the gradient and momentum optimizer. Both of these observations are demonstrated by the figure above.

## Library Functions

[`mnist`](@ref), [`mnist_data_loader`](@ref), the `DataLoader` constructor for labelled images,
[`split_and_flatten`](@ref) and [`onehotbatch`](@ref) are documented in the [Library](@ref) section
of the home page. This page deliberately does not repeat them: a docstring rendered in two places
makes every `@ref` to it resolve to whichever of the two Documenter saw last, which was this one, so
the reference on the home page linked away from itself.

`accuracy`, `ClassificationTransformer` and `ClassificationLayer` are documented in the
[`GeometricMachineLearning` reference](https://juliagni.github.io/GeometricMachineLearning.jl/latest/).

## References

```@bibliography
Pages = []
Canonical = false

brantner2023generalizing
```
