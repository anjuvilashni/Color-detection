import pandas as pd
import numpy as np
import matplotlib.pyplot as plt

import tensorflow as tf
from tensorflow.keras.datasets import cifar10
from tensorflow.keras.utils import to_categorical

from tensorflow.keras.models import Sequential
from tensorflow.keras.layers import (
    Dense,
    Conv2D,
    MaxPool2D,
    Flatten,
    Dropout,
    BatchNormalization,
)
from tensorflow.keras.callbacks import EarlyStopping
from tensorflow.keras.preprocessing.image import ImageDataGenerator

from sklearn.metrics import ConfusionMatrixDisplay
from sklearn.metrics import classification_report, confusion_matrix

(X_train, y_train), (X_test, y_test) = cifar10.load_data()

print(f"X_train shape: {X_train.shape}")
print(f"y_train shape: {y_train.shape}")
print(f"X_test shape: {X_test.shape}")
print(f"y_test shape: {y_test.shape}")

classes_name = [
    "Airplane",
    "Automobile",
    "Bird",
    "Cat",
    "Deer",
    "Dog",
    "Frog",
    "Horse",
    "Ship",
    "Truck",
]

classes, counts = np.unique(y_train, return_counts=True)
plt.barh(classes_name, counts)
plt.title("Class distribution in training set")

classes, counts = np.unique(y_test, return_counts=True)
plt.barh(classes_name, counts)
plt.title("Class distribution in testing set")

# Scale the data
X_train = X_train / 255.0
X_test = X_test / 255.0

# Transform target variable into one-hotencoding
y_cat_train = to_categorical(y_train, 10)
y_cat_test = to_categorical(y_test, 10)

INPUT_SHAPE = (32, 32, 3)
KERNEL_SIZE = (3, 3)
model = Sequential()

# Convolutional Layer
model.add(
    Conv2D(
        filters=32,
        kernel_size=KERNEL_SIZE,
        input_shape=INPUT_SHAPE,
        activation="relu",
        padding="same",
    )
)
model.add(BatchNormalization())
model.add(
    Conv2D(
        filters=32,
        kernel_size=KERNEL_SIZE,
        input_shape=INPUT_SHAPE,
        activation="relu",
        padding="same",
    )
)
model.add(BatchNormalization())
# Pooling layer
model.add(MaxPool2D(pool_size=(2, 2)))
# Dropout layers
model.add(Dropout(0.25))

model.add(
    Conv2D(
        filters=64,
        kernel_size=KERNEL_SIZE,
        input_shape=INPUT_SHAPE,
        activation="relu",
        padding="same",
    )
)
model.add(BatchNormalization())
model.add(
    Conv2D(
        filters=64,
        kernel_size=KERNEL_SIZE,
        input_shape=INPUT_SHAPE,
        activation="relu",
        padding="same",
    )
)
model.add(BatchNormalization())
model.add(MaxPool2D(pool_size=(2, 2)))
model.add(Dropout(0.25))

model.add(
    Conv2D(
        filters=128,
        kernel_size=KERNEL_SIZE,
        input_shape=INPUT_SHAPE,
        activation="relu",
        padding="same",
    )
)
model.add(BatchNormalization())
model.add(
    Conv2D(
        filters=128,
        kernel_size=KERNEL_SIZE,
        input_shape=INPUT_SHAPE,
        activation="relu",
        padding="same",
    )
)
model.add(BatchNormalization())
model.add(MaxPool2D(pool_size=(2, 2)))
model.add(Dropout(0.25))

model.add(Flatten())
# model.add(Dropout(0.2))
model.add(Dense(128, activation="relu"))
model.add(Dropout(0.25))
model.add(Dense(10, activation="softmax"))

METRICS = [
    "accuracy",
    tf.keras.metrics.Precision(name="precision"),
    tf.keras.metrics.Recall(name="recall"),
]
model.compile(loss="categorical_crossentropy", optimizer="adam", metrics=METRICS)

model.summary()

early_stop = EarlyStopping(monitor="val_loss", patience=2)

batch_size = 32
data_generator = ImageDataGenerator(
    width_shift_range=0.1, height_shift_range=0.1, horizontal_flip=True
)
train_generator = data_generator.flow(X_train, y_cat_train, batch_size)
steps_per_epoch = X_train.shape[0] // batch_size

r = model.fit(
    train_generator,
    epochs=50,
    steps_per_epoch=steps_per_epoch,
    validation_data=(X_test, y_cat_test),
    #               callbacks=[early_stop],
    #               batch_size=batch_size,
)

plt.figure(figsize=(12, 16))

plt.subplot(4, 2, 1)
plt.plot(r.history["loss"], label="Loss")
plt.plot(r.history["val_loss"], label="val_Loss")
plt.title("Loss Function Evolution")
plt.legend()

plt.subplot(4, 2, 2)
plt.plot(r.history["accuracy"], label="accuracy")
plt.plot(r.history["val_accuracy"], label="val_accuracy")
plt.title("Accuracy Function Evolution")
plt.legend()

plt.subplot(4, 2, 3)
plt.plot(r.history["precision"], label="precision")
plt.plot(r.history["val_precision"], label="val_precision")
plt.title("Precision Function Evolution")
plt.legend()

plt.subplot(4, 2, 4)
plt.plot(r.history["recall"], label="recall")
plt.plot(r.history["val_recall"], label="val_recall")
plt.title("Recall Function Evolution")
plt.legend()

evaluation = model.evaluate(X_test, y_cat_test)
print(f"Test Accuracy : {evaluation[1] * 100:.2f}%")

y_pred = model.predict(X_test)
y_pred = np.argmax(y_pred, axis=1)
cm = confusion_matrix(y_test, y_pred)


disp = ConfusionMatrixDisplay(confusion_matrix=cm, display_labels=classes_name)


# NOTE: Fill all variables here with default values of the plot_confusion_matrix
fig, ax = plt.subplots(figsize=(10, 10))
disp = disp.plot(xticks_rotation="vertical", ax=ax, cmap="summer")

plt.show()

print(classification_report(y_test, y_pred))

model.save("cnn_20_epochs.h5")
